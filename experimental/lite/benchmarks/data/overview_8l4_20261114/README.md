# Eight-L4 GPU and SHM overview figures

All six ordinary-call figures now use **fresh 1 KiB–1 GiB measurements** from
[the full refresh](../full_refresh_8l4_20261114/README.md). There are no historical
tails or reused GPU/SHM UCCL curves. BF16; AllReduce in place, AllGather and
ReduceScatter out of place. Sizes denote complete AR/RS input or AG output per
GPU. Each figure has 1-KiB–1-MiB latency and 1-MiB–1-GiB bus-throughput panels;
both panels include 1 MiB.

## Measurement and selection

Every point comes from two fresh opposite-order sweeps: five warmups, three
rotated repetitions of ten checked timed calls per backend and size. The second
sweep reverses testbed, operation, size and initial backend order. All producer
streams finish before timing. The timer is the slowest-GPU CUDA-event interval,
including host submission gaps. Every output element and guard is checked on
every warmup and timed call. The base router is also measured and retained in
the underlying dataset, but does not replace a losing current candidate.

Both testbeds use the same fixed UCCL schedule:

| Collective | Complete bytes/GPU | UCCL implementation |
| --- | --- | --- |
| AR | 1 KiB–4 MiB | Tuned router: GPU reduction/progress through 8 KiB; compact CPU reduction thereafter |
| AR | 8 MiB–1 GiB | CPU NUMA reduction, regular 23-worker pool and 64-block cap, batch publication and parallel submission |
| AG | 1–128 KiB | Tuned packet router with GPU progress |
| AG | 256 KiB–1 MiB | Mini-host cooperative kernel, 16 blocks |
| AG | 2 MiB–1 GiB | Full per-source GPU-progress packet router, 64-block cap |
| RS | 1 KiB–1 GiB | GPU reduction/progress through 64 KiB and at 128 KiB; CPU NUMA reduction thereafter, with four active workers at 256 KiB–1 MiB |

This schedule was fixed before the full sweeps; it is not a per-size minimum or
an automatic-routing policy. The report retains regressions against the base
router and NCCL. All six plotted NCCL curves are paired with their UCCL samples
in the same experiment.

GPU mode leaves NCCL P2P policy at its default. SHM mode explicitly disables
CUDA peer access and NCCL P2P. The recorded initialization probes show 16 SHM
channel edges in **both** modes on this host, so these curves must not be
interpreted as measured P2P-versus-SHM transport throughput. UCCL uses mapped
host memory in both modes. See the raw transport evidence in the full refresh.

## Resident figure

`collectives-8l4-resident-small.svg` remains a separate earlier experiment. Its
1–64-KiB host-blocking resident measurements and NCCL graph controls come from
[the compact transfer study](../transfer_4to8_20261114/README.md). No resident
number is inserted into the freshly measured ordinary-call overviews, and no
resident result is extrapolated to 1 GiB.

## Reproduction

[summary.csv](summary.csv) contains exactly **126 fresh points**, including
implementation labels and the common source path. First run
`python3 scripts/summarize_full_8l4.py` from the Lite root; it rejects missing
runs, samples, or size points. Then run:

```bash
python3 benchmarks/data/overview_8l4_20261114/build.py
python3 benchmarks/data/overview_8l4_20261114/plot.py --preview
```

`build.py` rejects historical or incomplete inputs. `plot.py` writes six SVGs
under `docs/assets/` and PNG/PDF previews under `build/figures/`. Throughput is
decimal GB/s, `bytes / latency_us / 1000`, scaled by 14/8 for AR and 7/8 for
AG/RS. Source and figure hashes are recorded in `provenance.json`, and this
dataset is covered by `checksums.json`. Earlier figures and measurements remain
in Git history and their original datasets.
