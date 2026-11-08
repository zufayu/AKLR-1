---
title: "bf16 GEMM, N 7168 × K 768–4224 and N 18432 / 20480 × K 1536 / 7168 (Kimi-K3) — one column band of B per workgroup at m ≤ 112, a tiled 8-wave grid that turns persistent at m 9397 and 16384; additional exact small-M cases: N 1024 × K 7168; N 4096 × K 2048; N 6144 × K 1536; N 6144 × K 4096"
kind: case
ops: [gemm]
dtypes: [bf16]
regimes: ["M 7-112", "M 893-16384", "N=1024 K=7168 M={1,2,4,8,16,32,64,128}", "N=4096 K=2048 M={1,2,4,8,16,32,64,128}", "N=6144 K=1536 M={1,2,4,8,16,32,64,128}", "N=6144 K=4096 M={1,2,4,8,16,32,64,128}"]
contract: bitwise
gens: [gfx950]
flydsl: 0.3.2
basis: measured N=1
measured:
  - {metric: "speedup over aiter, local validate lower bound per Point; no CI measurement on main", value: "0.994–1.162; 5 of 17 Points ≥ 1.03 (m 80, 893, 2732, 9397, 16384); 0 served", gpu: MI355X, workload: "gemm_n7168_k768, m 8, 12, 16, 24, 32, 40, 48, 56, 60, 64, 80, 96, 112, 893, 2732, 9397, 16384", run_ref: "local:/workspace/code/gpt_oss_docker/work/sikl/k3_forge/final_r2_local/report.md:16", date: "2026-10-26"}
  - {metric: "speedup over aiter, local validate lower bound per Point; no CI measurement on main", value: "0.999–1.273; 14 of 17 Points ≥ 1.03; 0 served", gpu: MI355X, workload: "gemm_n7168_k1536, m 8–16384 (17 Points)", run_ref: "local:/workspace/code/gpt_oss_docker/work/sikl/k3_forge/final_r2_local/report.md:33", date: "2026-10-26"}
  - {metric: "speedup over aiter, local validate lower bound per Point; no CI measurement on main", value: "1.256–1.634; 11 of 11 Points ≥ 1.03; 0 served", gpu: MI355X, workload: "gemm_n7168_k1792, m 7, 14, 21, 28, 35, 42, 49, 56, 70, 84, 98", run_ref: "69e77013e (commit message table; branch kyle/skill-kernel-loop)", date: "2026-10-25"}
  - {metric: "speedup over aiter, local validate lower bound per Point; no CI measurement on main", value: "0.945–1.366; 16 of 17 Points ≥ 1.03; 0 served", gpu: MI355X, workload: "gemm_n7168_k3584, m 8–16384 (17 Points)", run_ref: "local:/workspace/code/gpt_oss_docker/work/sikl/k3_forge/final_r2_local/report.md:50", date: "2026-10-26"}
  - {metric: "speedup over aiter, local validate lower bound per Point; no CI measurement on main", value: "0.935–1.256; 15 of 17 Points ≥ 1.03 (not m 2732, 16384); 0 served", gpu: MI355X, workload: "gemm_n7168_k4224, m 8–16384 (17 Points)", run_ref: "local:/workspace/code/gpt_oss_docker/work/sikl/k3_forge/final3_local/validate/report.md:61 and local:/workspace/code/gpt_oss_docker/.claude/memory/project_k3_bf16_gemm_agent_kernels.md:127", date: "2026-10-26"}
  - {metric: "speedup over aiter, local validate lower bound per Point; no CI measurement on main", value: "1.284–2.000 (2.000 is the bound's cap); 13 of 13 Points ≥ 1.03; 0 served", gpu: MI355X, workload: "gemm_n18432_k1536, m 8, 12, 16, 24, 32, 40, 48, 56, 60, 64, 80, 96, 112", run_ref: "95fb1e68a (commit message table; branch kyle/skill-kernel-loop)", date: "2026-10-25"}
  - {metric: "speedup over aiter, local validate lower bound per Point; no CI measurement on main", value: "1.071–1.417; 23 of 23 Points ≥ 1.03; 0 served", gpu: MI355X, workload: "gemm_n20480_k7168, m 7–112 (23 Points)", run_ref: "local:/workspace/code/gpt_oss_docker/work/sikl/k3_forge/final3_local/validate/report.md:16", date: "2026-10-26"}
  - {"metric": "whole-call per-Point baseline speedup; local AKLR audit/bench, not CI", "value": "8/8 Points qualify under default rule; representative ratios in small-M implementation evidence; full Point records in local mapping", "gpu": "MI355X", "workload": "gemm_n1024_k7168, UUID 4c0839a9bd82123e, M 1, 2, 4, 8, 16, 32, 64, 128", "run_ref": "local:/tmp/inf3_validation_checkpoint_0142/results/g3/bf16_small_4c0839a9bd82123e/validation/report.json", "date": "2026-11-08"}
  - {"metric": "whole-call per-Point baseline speedup; local AKLR audit/bench, not CI", "value": "8/8 Points qualify under default rule; representative ratios in small-M implementation evidence; full Point records in local mapping", "gpu": "MI355X", "workload": "gemm_n4096_k2048, UUID 37c909c4b629ad59, M 1, 2, 4, 8, 16, 32, 64, 128", "run_ref": "local:/tmp/inf3_validation_checkpoint_0142/results/g4/bf16_small_37c909c4b629ad59/validation/report.json", "date": "2026-11-08"}
  - {"metric": "whole-call per-Point baseline speedup; local AKLR audit/bench, not CI", "value": "8/8 Points qualify under default rule; representative ratios in small-M implementation evidence; full Point records in local mapping", "gpu": "MI355X", "workload": "gemm_n6144_k1536, UUID 1d3a1fcaf77631e1, M 1, 2, 4, 8, 16, 32, 64, 128", "run_ref": "local:/tmp/inf3_validation_checkpoint_0142/results/g3/bf16_small_1d3a1fcaf77631e1/validation/report.json", "date": "2026-11-08"}
  - {"metric": "whole-call per-Point baseline speedup; local AKLR audit/bench, not CI", "value": "8/8 Points qualify under default rule; representative ratios in small-M implementation evidence; full Point records in local mapping", "gpu": "MI355X", "workload": "gemm_n6144_k4096, UUID 3e2804d64ce6b4c7, M 1, 2, 4, 8, 16, 32, 64, 128", "run_ref": "local:/tmp/inf3_validation_checkpoint_0142/results/g4/bf16_small_3e2804d64ce6b4c7/validation/report.json", "date": "2026-11-08"}
sources:
  - aklr/ops/gemm/impls/flydsl/gemm_n7168_k768/0567a6d854ac7a39.json
  - aklr/ops/gemm/impls/flydsl/gemm_n7168_k1536/c9ad7a129bb4cfe6.json
  - aklr/ops/gemm/impls/flydsl/gemm_n7168_k1792/f0a48d1c7cdce51f.json
  - aklr/ops/gemm/impls/flydsl/gemm_n7168_k3584/251a5ceb2d416e55.json
  - aklr/ops/gemm/impls/flydsl/gemm_n7168_k4224/2d72ae169867a6d1.json
  - aklr/ops/gemm/impls/flydsl/gemm_n18432_k1536/8cffee60e0ddc139.json
  - aklr/ops/gemm/impls/flydsl/gemm_n20480_k7168/23c7fb06d509a1bf.json
  - aklr/ops/gemm/impls/flydsl/gemm_n1024_k7168/4c0839a9bd82123e.json
  - aklr/ops/gemm/impls/flydsl/gemm_n4096_k2048/37c909c4b629ad59.json
  - aklr/ops/gemm/impls/flydsl/gemm_n6144_k1536/1d3a1fcaf77631e1.json
  - aklr/ops/gemm/impls/flydsl/gemm_n6144_k4096/3e2804d64ce6b4c7.json
---

# bf16 GEMM at N 7168, 18432 and 20480 (Kimi-K3): a column band of B per workgroup, then a tiled grid — historical collection and additional exact small-M cases

The original collection below describes the historical Kimi-K3 kernels and Points. The additional exact small-M shapes are scoped separately in the small-M implementation evidence section; they do not expand the historical measurements or imply Kimi-K3 model provenance.


Seven FlyDSL kernels for the `gemm@1.0` contract on Kimi-K3 shapes (definitions #69, kernels #115, merge
a8fe490b1), one schema file per shape, written by forge-loop campaigns and reviewed. Each schema embeds its
kernel as `kernel.sources[0].content` (`kernel.py`); function names below are in that file. "m" is the Point's M.

## Applies when

- Contract `gemm@1.0`, layout variant `row_major` (`b.is_shuffled` false): `a` (m, k) and `b` (n, k) bf16,
  `trans_b`, no bias, bf16 `out`. `compare` is bitwise (`determinism: bitwise`, `max_violation_fraction` 0.0,
  the `CompareSpec` defaults), with the fp32 dot-product error bound of `_dot_k()` (`GEMM` in
  `aklr/ops/gemm/contract.py`).
- N × K = 7168 × 768, 1536, 1792, 3584, 4224 (a weight of 10.5–57.75 MiB), 18432 × 1536 (54 MiB) and
  20480 × 7168 (280 MiB): at m ≤ 112 each call streams the whole weight once
  (`../gemm/small_m.md` §2). k1792 and n18432 / n20480 have only decode Points (m ≤ 112); the other
  four also have m 893, 2732, 9397, 16384.
- Each schema name has only this file (no file of another language or an older kernel under the same name on
  main), so at every Point the yardstick is aiter.
- **No Point of these files is served today.** No CI run has written `speedup` or `accuracy` into their
  `workloads` (main at 0cef4f2e3); dispatch serves a workload only from `AKLR_MIN_SPEEDUP` 1.03 and falls back with
  `not_measured` (`aklr/ops/README.md` § Environment variables; `aklr/core/contract/spec/_workloads.py:38`).

## Counter-signals

- **Below 1.03 in the local validate** (the numbers CI has not yet confirmed or contradicted):
  - k768 at m 8–64, 96 and 112: 0.994–1.027 *(field, E1)*. These Points run the skinny, ring and small-tile paths
    below; the commit that added the kernel notes aiter is tuned for this shape.
  - k1536 at m 32 (1.005), 893 (1.025) and 16384 (0.999) *(field, E2)*; k3584 at 16384 (0.945) *(field, E4)*;
    k4224 at 2732 (1.020) and 16384 (0.935) *(field, E5, E6)*. At m 16384 all three run the persistent
    256×256 grid below.
  - Decode Points this close to 1.03 cross it between runs: k768's m 32 read 1.002 in one run and 1.029 and 1.038
    in the two arms of another, all three with the same final ISA at that Point (the large-m rework was delivered
    with the ISA at m ≤ 893 unchanged) *(field, E1)*.
- **k4224 at m 56–112 folds a cross-workgroup split-K through flags whose tag does not change between calls.**
  `_sk_build`: the last split polls `MAGIC ^ tile ^ split<<16` words in a workspace allocated by `torch.empty`
  each call, at most 65536 polls with `s_sleep 1`, stores NaN if a producer has not arrived, and clears the flags
  with plain stores. The fold order is fixed (planes 0, 1, … then its own), so the result is bitwise stable, but a
  flag word is read before this call writes it: correctness depends on the previous call having cleared it.
  `aklr/ops/README.md` § The kernel section and ABI asks for scratch rewritten before it is read; zeroing
  flags on every call (`../gemm/small_m.md` §4) removes the dependency. Its docstring
  (`_sk_count_ready`) says "this call's tag".
- **A cross-workgroup split lost on k1792's grid.** A one-launch split-K 2 with a flag hand-off measured 9.89 µs at
  m 7 to 15.76 µs at m 98, worse at every Point than the single-pass kernel (6.13–11.55 µs) *(field, E18)*.
- **Stale docstring.** k768's module docstring says one launch per call; at m 9397 `_launcher` runs a head
  launch over 9216 rows and a tail launch over 181 (as do k1536, k3584 and k4224 at m 9397, whose docstrings do not
  claim one launch).
- **`run` departs from the ABI.** n20480's `run` takes `out=None`, allocates the output and returns it when no
  `out` is passed (`aklr/ops/README.md` § The kernel section and ABI: `run` never allocates or returns an output).
  AKLR passes `out`, so no Point reaches that branch.
- **Hard-coded device.** n18432 and n20480 launch exactly 256 workgroups and divide N by 256; k1792, k3584 and
  k4224 add `256 − 224` L2-prefetch workgroups; the persistent grids walk tiles 256 apart. On fewer CUs the kernels
  still compute the right result, but the one-workgroup-per-CU design no longer holds (read in the code).
- **Code no Point reaches:** k3584's `_CONFIGS` rows 128 and 2731, k4224's row 128 and k1536's row 2731 (the
  Points jump from 112 to 893 and from 893 to 2732); k1792's `m <= 48` branch of `_config` (no Point between 43
  and 48).
- **Columns computed and dropped.** n18432 and n20480 compute 96-wide (or 80-wide) tiles for 72 or 80 stored
  columns; B rows past the real ones read zero past the buffer bound or come from LDS rows no DMA writes, and
  feed only unstored columns.

## Mechanism

Shared by the seven kernels:

- **MFMA `mfma_f32_16x16x32_bf16` with B as the first operand**, so a lane's four fp32 results are four
  consecutive output columns of one row and C leaves as 8- or 16-byte stores (`../gemm/epilogue.md`
  §3); k4224's split-K path keeps A first.
- **A and B into LDS by buffer→LDS DMA** (inline `buffer_load_dwordx4 … lds`, 16 B per lane), XOR-swizzled by
  16-byte chunk, in multi-stage rings (`../gemm/datapath.md` §2, §5); k768's skinny path (m ≤ 16) is
  the exception: A staged once in LDS from registers, B straight from global into registers.
- **No K split across workgroups** except k4224 at m 56–112. Where waves of one workgroup split K, an owner wave
  adds the partials from LDS in wave order; every output is one fp32 sum in an order fixed per output.
  K-start staggers (k1792, k3584, k4224, n18432, n20480) change where a workgroup's K loop starts, the same on
  every call.
- **A per-m configuration table** compiled in a `functools.cache` function on a Point's first call.

**m ≤ 112: one workgroup per column band, the whole K inside it.**

| | k1792 (all Points), k3584 (m ≤ 112), k4224 (m ≤ 48) | k768 (m ≤ 112) | k1536 (m ≤ 112) | n18432, n20480 (all Points) |
|---|---|---|---|---|
| Function | `_kernels` (k3584's `gemm_n7168_k3584_skinny` is k1792's kernel line for line) | `_build_skinny` (m ≤ 16), `_build_ring` (24, 32), `_build_large` (40–112) | `_build_tiled` | `_build_tiled` |
| Grid | 224 bands of 32 columns (64 split by rows between two workgroups of one XCD at m ≥ 84 / 80), + 32 L2-prefetch workgroups from m 28 / 24 | 224 workgroups | 224 workgroups | 256, one per CU; workgroup i stores 64 line-aligned columns plus an 8- (n18432) or 16-column (n20480) slice of a strip region, the slices of one XCD adjacent |
| Waves, K split | 4 or 8 waves; K over 2 or 4 waves at most m, none at m 21 and 98 (k1792) | 4 waves each a quarter of K (m ≤ 16); 3 waves each a third, wave-private DMA ring of 4 step pairs, `s_setprio` around the MFMAs (24, 32); 2–4 waves, tiles 48×32, 64×32, 48×64, 64×64, 4–5 stages (40–112) | 16×32 to 64×64 tiles, 2–8 waves, 4–6 stages | tile 16–128 × 96 (80 at m ≥ 98), 2–4 waves, 5 stages (m ≤ 32) or 3 |
| Loads | separate A and B rings (depths 8 to 3 by m); B `nt` | m ≤ 16: A once into LDS, B straight from global into registers; m ≥ 24: A and B by DMA (`sc0`) | B `nt` at most Points | A `sc0`, B `sc0 nt`; each stage's DMAs spread over the first two K steps, A first; fragments read one K step ahead |
| Other | K start staggered per band (×3 mod K tiles) from m 35 / 40; partials placed clear of the last tile's ring slots so the fold needs no extra barrier; kernel pointers preloaded into SGPRs | — | operand-swapped stores | K start staggered per workgroup; waves with no rows below m skip the last A DMA at m 33–64; kernel pointers preloaded |

The L2-prefetch workgroups DMA later B tiles of their XCD's bands into LDS and discard them, so the compute
workgroups find them in L2 (`../gemm/small_m.md` §6). k4224 at m 56–112 instead splits K 3 ways
(64×96 or 96×96 tiles, 225 workgroups) or 2 ways (112×64, 224 workgroups) with the last-split fold described
under Counter-signals (`../gemm/grid_pricing.md` §2).

**m 893–16384 (k768, k1536, k3584, k4224): a tiled async-LDS HGEMM, persistent at the two largest m.**

| m | k768 | k1536 | k3584 | k4224 |
|---|---|---|---|---|
| 893 | 128×128, 8 waves, 2 stages; 392 workgroups | 128×128, 4 waves, 2 stages; 392 | 128×224, 8-wave pipeline, 3 stages; 224 | 112×224, 7 waves, 3 stages; 256 |
| 2732 | 160×128, 4 waves, 2 stages; 1008 | 160×256, 8-wave pipeline, 3 stages; 504 | 160×256, 8-wave pipeline, 3 stages; 504 | 160×256, 8-wave pipeline, 3 stages; 504 |
| 9397 | persistent 256×256 over the first 9216 rows (1008 tiles on 256 workgroups) + a 96×64 tail launch over 181 rows | same | same | same |
| 16384 | persistent 256×256, 1792 tiles, 7 per workgroup | same | same | same |
| C stores `nt` | m 893, 2732, 16384 | m 2732–16384 | every tiled Point | every tiled Point |

- **The 8-wave pipeline** interleaves the next stage's DMAs with the MFMA clusters of the first K step, reads
  each fragment one cluster ahead, raises `s_setprio` around the clusters and pins the order with a
  `sched_group_barrier` table (`../gemm/mainloop.md` §2, `../gemm/schedule_and_locality.md`
  §3).
- **The persistent walk:** 256 workgroups take tiles 256 apart; after the last K stage's barrier each loads the
  next tile's first stage, then finishes the current tile, and each wave stages its C sub-tile through a private
  LDS slice past the operand ring, so the epilogue needs no workgroup barrier
  (`../gemm/grid_pricing.md` §10).
- **Tile order:** each XCD takes a contiguous run of tiles, walked a few block rows (`GROUP_M` 3–7) at a time
  (`../gemm/schedule_and_locality.md` §2); k768 and k1536 keep the linear order at m 893.

**What each part bought** (campaign ablations; each kept round timed beside the version before it):

- k1792: the single-pass ring with a fixed-order K-wave fold +3.5% (m 98) to +50.6% (m 35) over the campaign's
  starting kernel; the K-start stagger +0.2–8.4% at m ≥ 35; the row split at m 84, 98 +6.4–6.6%; per-m wave layouts
  +12.9% at m 98; kernel-argument preload +2.0–4.3% at every Point; `nt` on B +0.6–3.4% up to m 84. The L2-prefetch
  workgroups measured −3.3% to +2.6% by Point *(field, E9)*.
- k3584: the skinny/tiled pair +17.2–45.7% at m ≤ 112 *(field, E10)*; the persistent grid +1.5% (m 9397) and
  +0.9% (16384) *(field, E14)*.
- k4224: the k3584 design ported +24.2–107.5% at m ≤ 893; the split-K over one M block +3.6–10.4% at m 56–112;
  an exact one-round 112×224 tile +6.7% at m 893 *(field, E11)*; the persistent grid +1.4% (9397) and +2.6% (16384)
  in a same-process paired bench *(field, E17)*.
- k768: A staged in LDS with fewer waves +6.7–46.1% at m ≤ 112; the per-wave DMA ring +6.7–13.6% at m 24–112 when
  added; small-tile deep pipelines for m 56–112 +1.9–7.7% *(field, E12)*; the 8-wave pipelined tile +5.4% at
  m 9397 and the persistent grid +6.1% (9397) and +6.5% (16384) *(field, E14)*.
- k1536: aiter's async-LDS HGEMM with a per-m table +17.0–42.9% at m ≤ 112 over the starting kernel; the 3-stage
  160×256 8-wave tile +25.2% at m 2732; the head + tail split at m 9397 +4.4% *(field, E13)*; `nt` C stores
  +1.0–2.4% at m ≥ 2732 and the persistent grid +3.5% (9397) and +3.6% (16384) *(field, E14)*.
- n18432: the one-workgroup-per-CU port +7.5–113.4%; 72-column blocks on all 256 CUs with A issued first +17.2% at
  m 112; the line-aligned block plus strip −0.4% to +3.1% *(field, E15)*. n20480 is that kernel at K 7168, kept in
  one round *(field, E16)*.

## Result

`speedup` is absent from every workload of these files: CI has not measured them, so dispatch serves none of
their 115 Points. When CI does measure them it runs the FlyDSL of its image (0.3.4.1 in
the image of the latest perf runs), not the 0.3.2 of the local numbers below
(`../pitfalls/measured_a_different_build.md`).

The only per-Point measurements are the campaigns' own `python -m sikl validate` runs on MI355X (the repository
before its rename to AKLR), FlyDSL 0.3.2: a lower bound of the CUDA-graph time ratio aiter / kernel, one run each,
capped at 2.000; "≥ 1.03" counts them against the dispatch threshold (that validate itself demoted below 1.02).

| File | m ≤ 112 | m 893 | m 2732 | m 9397 | m 16384 | ≥ 1.03 locally | Served |
|---|---|---|---|---|---|---|---|
| k768 *(field, E1)* | 0.994–1.056 | 1.092 | 1.127 | 1.162 | 1.106 | 5 of 17 | 0 |
| k1536 *(field, E2)* | 1.005–1.273 | 1.025 | 1.088 | 1.102 | 0.999 | 14 of 17 | 0 |
| k1792 *(field, E3)* | 1.256–1.634 | – | – | – | – | 11 of 11 | 0 |
| k3584 *(field, E4)* | 1.096–1.366 | 1.194 | 1.039 | 1.061 | 0.945 | 16 of 17 | 0 |
| k4224 *(field, E5, E6)* | 1.069–1.256 | 1.126 | 1.020 | 1.049 | 0.935 | 15 of 17 | 0 |
| n18432 *(field, E7)* | 1.284–2.000 | – | – | – | – | 13 of 13 | 0 |
| n20480 *(field, E8)* | 1.071–1.417 | – | – | – | – | 23 of 23 | 0 |

"–": no such Point. k4224's m ≤ 2732 values were measured on the version before the persistent grid was added for
m 9397 and 16384 (its diff to main changes those two config rows and adds the persistent path); m 9397 and 16384
are from the run on the delivered version *(field, E5, E6)*.


## small-M implementation evidence

The additions below extend these mechanisms to **discrete, tested Points only**; they do not change the older kernels or results above. Contract: `gemm@1.0`, `row_major`, A=(M,K), B=(N,K), bf16 input/output, `trans_b=True`, no bias. Reference accuracy uses `DotProductBound`; repeated-run determinism is bitwise with fixed element order and zero violation fraction. These are separate checks: accuracy is not bitwise equality to the reference.

**How to read the gains.** One independent local AKLR audit/bench task per implementation (N=1), followed by review; not CI or proof of deployment selection. All tested Points passed accuracy. Ratios are whole-call lower bounds against AITER tuned `gemm_a16w16` through `gemm_baseline`, not component ablations. No default-served incumbent (or only the same kernel) was found at the fixed base, so incumbent timing is unavailable. Representative gains below do not replace the full Point records.

Base/report head: `a12866b1e40e86ea6aff7ac24cbe5634132f6b2e`; candidates were untracked during measurement, so that commit does not identify their source. Worker records: AITER `0.1.21.dev66+gdbd8bf5bd`, FlyDSL 0.3.2, Torch `2.11.0+rocm10.0.0`, gfx950; report platform MI355X / ROCm `7.15.26333`. CI declares AITER `dbd8bf5bd624120197a7a26780a8c72201824f0f`; the short-version prefix and successful wheel install do not certify the full runtime commit. Complete runtime configuration/environment variables were not archived; receipts bind task identity only. Qualification is reconstructed from the [fixed-base official rules](../../../../aklr/ops/README.md), not the actual runtime `AKLR_MIN_SPEEDUP` or a published schema’s service status.

Profile v18: CUDA graphs, per-call L2 flush, seeded shuffled rounds, 16/32-round looks, alpha=0.025 per look; summed whole-call GPU duration, mean within replay, median across replays, Student-t lower bound on mean log-ratio. The source/report/receipt fingerprints and complete Point records remain in the local mapping and reports referenced by Evidence. Bounds determine entry before rounding; displayed speedups are rounded to three decimals.

**Transfer limits.** DMA, prefetch, tile ordering, priority, MFMA choice, and compiler hints are source facts, not independently measured causal gains. Cross-workgroup protocols still require separate checks of publication visibility, tag collisions/wraparound, scratch initialization, concurrent streams, graph replay, and unique fold ownership. A fixed sum order and passing whole-call checks do not establish protocol safety. Logical tile groups are not stream-invariant absolute XCD IDs or measured cache hits.

**Reproduce / rollback.** On MI355X with matching dependencies and kernel fingerprint, run `python -m aklr validate <schema> --base a12866b1e40e86ea6aff7ac24cbe5634132f6b2e` separately for each Evidence source. Inspect complete Points, findings, denominators, unrounded bounds, and environment, not just exit status. Archive local artifacts and repeat official validation before publication; adding published measurement fields changes the schema byte hash, not necessarily the kernel-content fingerprint. Roll back one candidate, not the whole contract; do not relax thresholds for non-qualifying Points. Disable a suspect hand-off pending separate validation.

### small-M N=1024, K=7168

At M=1,2, register GEMV assigns one output column to each wave. At M=4,8,16,32,64,128, four waves split K inside one workgroup, with B first in MFMA and wave-private XOR-swizzled LDS DMA rings. Lines 268–288 fold in wave order before bf16 conversion. The two GEMV Points do not demonstrate an MFMA benefit. *(source, S101; embedded `kernel.py` line numbers)*

**Representative result:** M=1 reached 1.478×; M=128 reached 1.085×. All authored/tested Points for this candidate qualify under the reconstructed default rule; unlisted M values remain untested. *(field, E101)*

### small-M N=4096, K=2048

Independent A/B LDS DMA rings feed B-first MFMA. The four-wave layout partitions M/N/K as (1,1,4) at M=1,2,4,8,16, (1,2,2) at M=32, and (2,2,1) at M=64,128. Only wk>1 requires a K-slice LDS fold: not every Point is wave split-K. Lines 279–298 finish and reduce; 308–339 compile and invoke a single launch. *(source, S105; embedded `kernel.py` line numbers)*

**Representative result:** M=16 reached 1.464×; M=128 reached 1.163×. All authored/tested Points for this candidate qualify under the reconstructed default rule; unlisted M values remain untested. *(field, E105)*

### small-M N=6144, K=1536

M=1,2,4,8 use two N-waves with wk=1; M=16,32 use four waves (1,2,2), M=64 eight waves (2,2,2), and M=128 sixteen waves (2,4,2), partitioned along M/N/K. Independent A/B DMA rings feed BF16 MFMA; wk>1 adds an LDS fold. Lines 252–354 also contain non-output B-prefetch workgroups and the constant configurations. Prefetch exists in the source, but neither its isolated benefit nor actual L2 hits were measured. *(source, S107; embedded `kernel.py` line numbers)*

**Representative result:** M=1 reached 1.637×; M=64 reached 1.458×. All authored/tested Points for this candidate qualify under the reconstructed default rule; unlisted M values remain untested. *(field, E107)*

### small-M N=6144, K=4096

One launch streams column strips of B, splits K over workgroup waves, and feeds 16×16×32 BF16 MFMA through A/B XOR-swizzled LDS DMA rings. `_SKINNY` selects ring depth, K-start rotation, and row splitting; lines 153–166 remap tile indices. These are logical layout choices, not evidence of an absolute XCD assignment or a causal benefit from the rotation. *(source, S108; embedded `kernel.py` line numbers)*

**Representative result:** M=4 reached 1.321×; M=128 reached 1.142×. All authored/tested Points for this candidate qualify under the reconstructed default rule; unlisted M values remain untested. *(field, E108)*

## Reproduce

On an MI355X with the repository's FlyDSL 0.3.2, from the repository root, one schema at a time:

```
python -m aklr validate aklr/ops/gemm/impls/flydsl/gemm_n7168_k768/0567a6d854ac7a39.json
python -m aklr validate aklr/ops/gemm/impls/flydsl/gemm_n7168_k1536/c9ad7a129bb4cfe6.json
python -m aklr validate aklr/ops/gemm/impls/flydsl/gemm_n7168_k1792/f0a48d1c7cdce51f.json
python -m aklr validate aklr/ops/gemm/impls/flydsl/gemm_n7168_k3584/251a5ceb2d416e55.json
python -m aklr validate aklr/ops/gemm/impls/flydsl/gemm_n7168_k4224/2d72ae169867a6d1.json
python -m aklr validate aklr/ops/gemm/impls/flydsl/gemm_n18432_k1536/8cffee60e0ddc139.json
python -m aklr validate aklr/ops/gemm/impls/flydsl/gemm_n20480_k7168/23c7fb06d509a1bf.json
```

The report goes to `aklr_validation/report.md`; a local run checks the file, the served numbers are CI's
(`aklr/ops/README.md` § Workflow). Add `--base origin/main` only on a branch that edits the file: with the base set,
bench measures only schemas that are not at the base, so on an unchanged checkout it skips the bench
(`aklr/core/validation/stages/validation_scope.py`, `of_working_tree`). To read a kernel:
`git show <rev>:<schema> | python3 -c 'import json,sys; print(json.load(sys.stdin)["kernel"]["sources"][0]["content"])'`.

## Rollback

Delete the schema file: its Points go unserved, since no other file serves them. `AKLR_DISABLE=gemm@1.0`
stops serving the whole contract, every other bf16 GEMM schema included. Until CI writes `speedup`, nothing is
served and nothing needs rolling back; afterwards a Point measured below 1.03 is not served, and a `failed`
accuracy never is. Roll back for a wrong result CI does not catch: a NaN or stale fold from k4224's flags at
m 56–112 after an aborted or timed-out launch, or a change of FlyDSL or LLVM.

## Evidence

### small-M evidence and source references

Local post-measurement review: `schemas[id=<group>_<UUID>]` in local:/workspace/code/gpt_oss_docker/sync/inference3/postprocess_1107/operator_validation_all32_reviewed.json. Complete Point records, source/schema/report/receipt SHA256s, environment/install-log locators, and the source-byte identity checks are retained in local:/workspace/code/gpt_oss_docker/sync/inference3/postprocess_1107/bf16_kernel_kb_mapping.json.

- E101 [2026-11, gfx950, FlyDSL 0.3.2, N=1, local AKLR profile-v18 whole-call] `4c0839a9bd82123e` / `gemm_n1024_k7168`: all authored Points accuracy passed; report local:/tmp/inf3_validation_checkpoint_0142/results/g3/bf16_small_4c0839a9bd82123e/validation/report.json; report SHA256 `b8844ae33a597943f167f6ce389a1aca29678503f93c01c92fe16f3630685647`. Qualification is reconstructed; no incumbent timing.
- S101 aklr/ops/gemm/impls/flydsl/gemm_n1024_k7168/4c0839a9bd82123e.json#kernel.py:301 executable branches; official kernel-content fingerprint `131553682bb7ab996af86ae9a365b24157b78125c0405df55344f36a3cef275f`. Untracked at measurement, not source contained in the report head commit.
- E105 [2026-11, gfx950, FlyDSL 0.3.2, N=1, local AKLR profile-v18 whole-call] `37c909c4b629ad59` / `gemm_n4096_k2048`: all authored Points accuracy passed; report local:/tmp/inf3_validation_checkpoint_0142/results/g4/bf16_small_37c909c4b629ad59/validation/report.json; report SHA256 `47d2a326f7892d436aec394dd1be9e3e21efefdb1fbe6bba477debfac5252eac`. Qualification is reconstructed; no incumbent timing.
- S105 aklr/ops/gemm/impls/flydsl/gemm_n4096_k2048/37c909c4b629ad59.json#kernel.py:45 executable branches; official kernel-content fingerprint `6cf9e18c5d8dbdcb7fc58fab117ee719d72a5e003e324b9a2481519d3b51fdb2`. Untracked at measurement, not source contained in the report head commit.
- E107 [2026-11, gfx950, FlyDSL 0.3.2, N=1, local AKLR profile-v18 whole-call] `1d3a1fcaf77631e1` / `gemm_n6144_k1536`: all authored Points accuracy passed; report local:/tmp/inf3_validation_checkpoint_0142/results/g3/bf16_small_1d3a1fcaf77631e1/validation/report.json; report SHA256 `cb117b3fe62f25f8356d82bd7b5beb9c0ed6f06828dfe7b701f4bb829a444aea`. Qualification is reconstructed; no incumbent timing.
- S107 aklr/ops/gemm/impls/flydsl/gemm_n6144_k1536/1d3a1fcaf77631e1.json#kernel.py:47 executable branches; official kernel-content fingerprint `95579edeaab3105e572000f4a6c339bb6af6fd57235ea730bd678cabcffd6c2d`. Untracked at measurement, not source contained in the report head commit.
- E108 [2026-11, gfx950, FlyDSL 0.3.2, N=1, local AKLR profile-v18 whole-call] `3e2804d64ce6b4c7` / `gemm_n6144_k4096`: all authored Points accuracy passed; report local:/tmp/inf3_validation_checkpoint_0142/results/g4/bf16_small_3e2804d64ce6b4c7/validation/report.json; report SHA256 `d69b9fe579fa33654b498c50a87215fea46c238e03d9163e9685282481b26c7b`. Qualification is reconstructed; no incumbent timing.
- S108 aklr/ops/gemm/impls/flydsl/gemm_n6144_k4096/3e2804d64ce6b4c7.json#kernel.py:99 executable branches; official kernel-content fingerprint `8301c14ce910616f46999f56de1568ff96cbccdaa5111b0d3721caf2376b22ef`. Untracked at measurement, not source contained in the report head commit.

`<schema>.json#kernel.py:<line>` is a line of the `kernel.py` a schema embeds in `kernel.sources`; "local validate"
is `python -m sikl validate` on MI355X in the campaign containers, the ratio lower bound over aiter per Point.

- E1 [2026-10, gfx950, FlyDSL 0.3.2, N=1, local validate] k768 delivered: m 8 0.994, 12 1.000, 16 1.005, 24 0.994, 32 1.002, 40 1.013, 48 1.015, 56 1.011, 60 1.004, 64 1.005, 80 1.056, 96 1.027, 112 1.010, 893 1.092, 2732 1.127, 9397 1.162, 16384 1.106; in another run with the earlier version (863ac289) and the large-m group's module (69639fe2) side by side, m 32 read 1.038 and 1.029, m ≤ 112 0.998–1.064 and 0.996–1.065; the delivery check compared the final ISA at m ≤ 893 (gemm_n7168_k768; local:/workspace/code/gpt_oss_docker/work/sikl/k3_forge/final_r2_local/report.md:16; local:/workspace/code/gpt_oss_docker/work/sikl/k3_forge/final_r2ab_local/report.md:16; local:/workspace/code/gpt_oss_docker/.claude/memory/project_k3_bf16_gemm_agent_kernels.md:131)
- E2 [2026-10, gfx950, FlyDSL 0.3.2, N=1, local validate] k1536: m 8 1.273, 12 1.094, 16 1.077, 24 1.077, 32 1.005, 40 1.073, 48 1.075, 56 1.052, 60 1.046, 64 1.035, 80 1.061, 96 1.033, 112 1.037, 893 1.025, 2732 1.088, 9397 1.102, 16384 0.999 (gemm_n7168_k1536; local:/workspace/code/gpt_oss_docker/work/sikl/k3_forge/final_r2_local/report.md:33)
- E3 [2026-10, gfx950, FlyDSL 0.3.2, N=1, local validate] k1792: m 7 1.517, 14 1.490, 21 1.422, 28 1.387, 35 1.634, 42 1.611, 49 1.569, 56 1.547, 70 1.508, 84 1.488, 98 1.256 (gemm_n7168_k1792; commit message of 69e77013e)
- E4 [2026-10, gfx950, FlyDSL 0.3.2, N=1, local validate] k3584: m 8 1.366, 12 1.173, 16 1.177, 24 1.234, 32 1.260, 40 1.257, 48 1.230, 56 1.176, 60 1.146, 64 1.142, 80 1.186, 96 1.135, 112 1.096, 893 1.194, 2732 1.039, 9397 1.061, 16384 0.945 (gemm_n7168_k3584; local:/workspace/code/gpt_oss_docker/work/sikl/k3_forge/final_r2_local/report.md:50)
- E5 [2026-10, gfx950, FlyDSL 0.3.2, N=1, local validate] k4224 before the persistent grid (eab03434): m 8 1.214, 12 1.199, 16 1.184, 24 1.121, 32 1.069, 40 1.191, 48 1.204, 56 1.245, 60 1.254, 64 1.249, 80 1.251, 96 1.256, 112 1.187, 893 1.126, 2732 1.020, 9397 1.041, 16384 0.923 (gemm_n7168_k4224; local:/workspace/code/gpt_oss_docker/work/sikl/k3_forge/final3_local/validate/report.md:61)
- E6 [2026-10, gfx950, FlyDSL 0.3.2, N=1, local validate] k4224 delivered: 15 of 17 Points ≥ 1.03, m 9397 1.049, m 16384 0.935 (gemm_n7168_k4224; KB note local:/workspace/code/gpt_oss_docker/.claude/memory/project_k3_bf16_gemm_agent_kernels.md:127)
- E7 [2026-10, gfx950, FlyDSL 0.3.2, N=1, local validate] n18432: m 8 2.000, 12 2.000, 16 2.000 (the bound's cap), 24 1.350, 32 1.336, 40 1.380, 48 1.373, 56 1.354, 60 1.346, 64 1.284, 80 1.521, 96 1.287, 112 1.416 (gemm_n18432_k1536; commit message of 95fb1e68a)
- E8 [2026-10, gfx950, FlyDSL 0.3.2, N=1, local validate] n20480: m 7 1.299, 8 1.170, 12 1.114, 14 1.146, 16 1.159, 21 1.071, 24 1.076, 28 1.078, 32 1.071, 35 1.217, 40 1.147, 42 1.171, 48 1.210, 49 1.264, 56 1.195, 60 1.172, 64 1.155, 70 1.417, 80 1.395, 84 1.147, 96 1.109, 98 1.242, 112 1.193 (gemm_n20480_k7168; local:/workspace/code/gpt_oss_docker/work/sikl/k3_forge/final3_local/validate/report.md:16)
- E9 [2026-10, gfx950, FlyDSL 0.3.2, N=?, forge-loop paired bench; remeasured rounds 3 pairs] k1792 ladder: ring + K-wave fold (recorded) +39.7, 36.8, 29.2, 24.7, 50.6, 48.2, 42.6, 38.6, 40.5, 25.8, 3.5% (m 7–98); stagger +0.2–8.4% at m 35–98; row split +6.6/+6.4% at m 84/98; wave layouts +12.9% at m 98; preload +2.0–4.3% (recorded); B `nt` +0.6–3.4% at m ≤ 84; L2 prefetch −3.3 to +2.6% (gemm_n7168_k1792; local:/workspace/code/gpt_oss_docker/work/sikl/dashboards_k3/gemm_n7168_k1792/forge_experiments/ablation.json)
- E10 [2026-10, gfx950, FlyDSL 0.3.2, N=?, forge-loop paired bench, recorded round] k3584 skinny/tiled pair +17.2–45.7% at m 8–112, +9.9% at 893, −7.3% at 16384 against the starting kernel (gemm_n7168_k3584; local:/workspace/code/gpt_oss_docker/work/sikl/dashboards_k3/gemm_n7168_k3584/forge_experiments/ablation.json)
- E11 [2026-10, gfx950, FlyDSL 0.3.2, N=?, forge-loop paired bench; remeasured rounds 3 pairs] k4224: port +26.3–107.5% at m ≤ 112 and +24.2% at 893 (recorded); split-K over one M block (recorded) +3.6, 5.8, 6.4, 9.0, 10.4, 6.7% at m 56, 60, 64, 80, 96, 112; 112×224 tile +6.7% at 893 (gemm_n7168_k4224; local:/workspace/code/gpt_oss_docker/work/sikl/k3_forge/final3_docs/gemm_n7168_k4224/ablation.md; local:/workspace/code/gpt_oss_docker/work/sikl/dashboards_k3/gemm_n7168_k4224/forge_experiments/ablation.json)
- E12 [2026-10, gfx950, FlyDSL 0.3.2, N=?, forge-loop paired bench; remeasured rounds 3 pairs] k768: A in LDS with fewer waves +6.7–46.1% at m ≤ 112 (recorded); DMA ring +6.7–13.6% at m 24–112 (recorded); deep-pipeline small tiles +3.3, 4.6, 3.4, 1.9, 3.1, 7.7% at m 56, 60, 64, 80, 96, 112 (remeasured) (gemm_n7168_k768; local:/workspace/code/gpt_oss_docker/work/sikl/dashboards_k3/gemm_n7168_k768/forge_experiments/ablation.json)
- E13 [2026-10, gfx950, FlyDSL 0.3.2, N=?, forge-loop paired bench; remeasured rounds 3 pairs] k1536: HGEMM port +17.0–42.9% at m ≤ 112 (recorded); 3-stage 160×256 8-wave tile +25.2% at 2732; head + tail at 9397 +4.4% (gemm_n7168_k1536; local:/workspace/code/gpt_oss_docker/work/sikl/dashboards_k3/gemm_n7168_k1536/forge_experiments/ablation.json)
- E14 [2026-10, gfx950, FlyDSL 0.3.2, N=3, forge-loop paired bench, group campaign] persistent grid: k768 +6.1/+6.5%, k1536 +3.5/+3.6%, k3584 +1.5/+0.9% at m 9397/16384; k768 8-wave tile +5.4% at 9397; k1536 `nt` C +2.4/+1.0/+1.6% at 2732/9397/16384 (r2_n7168; local:/workspace/code/gpt_oss_docker/work/sikl/dashboards_k3/r2_n7168/forge_experiments/ablation.json)
- E15 [2026-10, gfx950, FlyDSL 0.3.2, N=?, forge-loop paired bench; remeasured rounds 3 pairs] n18432: port +7.5–113.4% (recorded); 72-column blocks + A first +0.1–17.2%, +17.2% at m 112 (recorded); line-aligned block + strip −0.4 to +3.1% (gemm_n18432_k1536; local:/workspace/code/gpt_oss_docker/work/sikl/dashboards_k3/gemm_n18432_k1536/forge_experiments/ablation.json)
- E16 [2026-10, gfx950, FlyDSL 0.3.2, N=?, forge-loop paired bench, recorded round] n20480: the one kept round, the n18432 design at N 20480, +7.9–42.9% over the starting kernel (gemm_n20480_k7168; local:/workspace/code/gpt_oss_docker/work/sikl/dashboards_k3/gemm_n20480_k7168/forge_experiments/ablation.json)
- E17 [2026-10, gfx950, FlyDSL 0.3.2, N=?, same-process paired bench] k4224 persistent grid against the version before: outputs bitwise equal, +1.4% at m 9397, +2.6% at m 16384 (gemm_n7168_k4224; KB note local:/workspace/code/gpt_oss_docker/.claude/memory/project_k3_bf16_gemm_agent_kernels.md:124)
- E18 [2026-10, gfx950, FlyDSL 0.3.2, N=?, campaign driver bench] k1792: split-K 2 in one launch with a flag hand-off 9.89 µs at m 7 to 15.76 µs at m 98 against 6.13–11.55 µs for the single-pass kernel (gemm_n7168_k1792; local:/workspace/code/gpt_oss_docker/work/sikl/dashboards_k3/gemm_n7168_k1792/forge_experiments/lessons/iter_002.md:24)
- S1 aklr/ops/gemm/contract.py:128 `GEMM` with `_UNSHUFFLED_VARIANTS` (:124) and `_dot_k()` (:95, fp32, `max_split_k` 16); `CompareSpec` defaults bitwise at aklr/core/contract/spec/_args.py:217
- S2 aklr/ops/gemm/impls/flydsl/gemm_n7168_k1792/f0a48d1c7cdce51f.json#kernel.py:50 `_config`; L2-prefetch workgroups at :86 and :276; B `nt` at :221; B-first MFMA at :271; owner-wave fold in wave order at :357; kernel pointers preloaded at :396
- S3 aklr/ops/gemm/impls/flydsl/gemm_n7168_k3584/251a5ceb2d416e55.json#kernel.py:26 `_SKINNY`; tiled `_CONFIGS` at :419; tail launch `_TAIL_SPLITS` at :471 and `_launcher` at :475; persistent walk at :1041
- S4 aklr/ops/gemm/impls/flydsl/gemm_n7168_k4224/2d72ae169867a6d1.json#kernel.py:1102 `_SK_CONFIGS`; `_sk_count_ready` static tag at :1155; poll at :1409, NaN at :1428, flag clear at :1432, producer tag at :1443
- S5 aklr/ops/gemm/impls/flydsl/gemm_n7168_k768/0567a6d854ac7a39.json#kernel.py:28 `_CONFIGS`; `_PIPE_TAIL_SPLITS` at :46; two launches at :146; docstring "one launch per call" at :1
- S6 aklr/ops/gemm/impls/flydsl/gemm_n7168_k1536/c9ad7a129bb4cfe6.json#kernel.py:26 `_CONFIGS`; persistent walk at :625
- S7 aklr/ops/gemm/impls/flydsl/gemm_n20480_k7168/23c7fb06d509a1bf.json#kernel.py:32 `_CONFIGS`; strip slice at :219; B `sc0 nt` at :333; K stagger at :396; `run(..., out=None)` allocating at :472 (gemm_n18432_k1536 has the same lines up to :471)
