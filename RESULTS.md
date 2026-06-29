# ADL benchmarks: awkward3 (cuda.compute) vs baseline (released awkward, RawKernel)

Repo: `kmohrman/columnar_gpu` (ADL queries q1–q8). GPU: NVIDIA RTX 6000 Ada 49GB
(`CUDA_VISIBLE_DEVICES=1`). CUDA 13.3.

> All numbers below are from a single full re-run (100k/1M/10M, both envs). Both envs read
> parquet **GPU-direct via cudf 26.6** (force-installed alongside cuda.compute / RawKernel —
> see `cudf_inject_overrides.txt`). awkward3 includes the `ak.combinations` JIT cache-key fix
> (`patches/awkward3-combinations-cache-fix.patch`; see `perf/reports/PERF_REPORT.md`).
> Warm timings (one warm-up call, then a timed call), single GPU, one run each.

## Environments (uv)
- `.venv-awkward3`: editable awkward3 (cuda.compute backend) + local `cuda-cccl`.
- `.venv-baseline`: released **awkward 2.8.11** — the last release *before* cuda.compute
  (2.9.x already ships it). CuPy RawKernel GPU backend.
- **cudf 26.6** force-installed in **both** via `uv --override` (cudf's `numba-cuda<0.29`
  metadata pin is irrelevant at read time — libcudf is C++). Both read GPU-direct.

## Setup deviations / findings
1. **cudf restored, GPU-direct, in both envs.** The old conflict (cudf → `numba-cuda<0.29`
   → `cuda-core<1.0` vs cuda.compute's `cuda-core 1.0`) is metadata-only; forcing the pin
   lets cudf 26.6 coexist and `cudf.read_parquet` works at runtime. `gpu_read_cudf.py`
   wraps device buffers as awkward (flat → `from_cupy`; jagged → `count_elements()` offsets
   + `.elements` leaf), no host round-trip. Reader selectable via `AK_BENCH_READER=cudf|shim`.
   ⇒ **read/load are now comparable across backends**, not a shim artifact.
2. **Read path affects baseline robustness.** Baseline Q3 (`ValueError: Negative dimensions`)
   used to FAIL at ≥1M with the pyarrow shim; with cudf's clean int64-offset `ListOffsetArray`
   it now **succeeds at all scales**. So that "failure" was a read-layout artifact, not a
   compute-backend limit. (Q8 still fails — a genuine argmin bug, below.)
3. **cuda.compute added GPU sort/argsort** (absent in 2.8.11); ADL queries don't use them.
4. **Baseline Q8 still crashes** at every scale: `ak.argmin(axis=-1, keepdims=True)` on
   option-typed jagged data with empty sublists. Surfaces as `bad_alloc` (100k, via rmm),
   `Negative dimensions` (1M), `CUDA_ERROR_ILLEGAL_ADDRESS` (10M). awkward3 runs Q8 correctly.
5. **GPU selection gotcha:** CUDA default order is FASTEST_FIRST, so `CUDA_VISIBLE_DEVICES=1`
   could select the **T400 4GB**. Fix: `export CUDA_DEVICE_ORDER=PCI_BUS_ID` (in bench_all.sh).

## How to run
```
cd columnar_gpu
# warm per-query comparison (isolated subprocess per query); reader defaults to cudf:
bash bench_all.sh <parquet> logs/<out>.txt           # AK_BENCH_READER=shim for old path
../.venv-awkward3/bin/python format_results.py logs/<out>.txt
```

## Results — warm GPU **compute** time per query (JIT excluded), RTX 6000 Ada 49GB

Three configurations, so both the stock backend and our work are visible:
- **baseline** — awkward 2.8.11, CuPy RawKernel backend.
- **stock awkward3** — the upstream cuda.compute backend, unmodified.
- **+ our work** — awkward3 with our changes: the `ak.combinations` JIT cache-key fix
  (Q5/Q6/Q8; `patches/`), and the `select` / `segmented_reduce` rewrites for the host-bound
  queries (Q3→`query3c_gpu`, Q7→`query7c_gpu`). Q1/Q2/Q4 are unchanged from stock.

Speedups in parens are ÷ baseline (>1 = faster than RawKernel).

### 100k events — compute (ms)
| Query | baseline | stock awkward3 | + our work | our change |
|---|--:|--:|--:|---|
| Q1 | ~0 | ~0 | ~0 | — |
| Q2 | ~0 | ~0 | ~0 | — |
| Q3 | 4.8 | 6.9 (0.69×) | **0.33 (14×)** | select |
| Q4 | 3.3 | 3.0 (1.11×) | 3.0 (1.11×) | — |
| Q5 | 2028 | 2303 (0.88×) | **34.9 (58×)** | combinations fix |
| Q6 | 2158 | 3496 (0.62×) | **91.4 (24×)** | combinations fix |
| Q7 | 96.1 | 99.9 (0.96×) | **4.0 (24×)** | segmented_reduce + perm |
| Q8 | CRASH | 4640 (ak3-only) | **123.3** | combinations fix |

### 1M events — compute (ms)
| Query | baseline | stock awkward3 | + our work | our change |
|---|--:|--:|--:|---|
| Q1 | ~0 | ~0 | ~0 | — |
| Q2 | ~0 | ~0 | ~0 | — |
| Q3 | 9.3 | 16.6 (0.56×) | **0.43 (22×)** | select |
| Q4 | 5.1 | 3.6 (1.41×) | 3.6 (1.41×) | — |
| Q5 | 19949 | 2319 (8.6×) | **59.2 (337×)** | combinations fix |
| Q6 | 21228 | 4069 (5.2×) | **594 (36×)** | combinations fix |
| Q7 | 207.4 | 228.1 (0.91×) | **19.1 (11×)** | segmented_reduce + perm |
| Q8 | FAIL | 4793 (ak3-only) | **243** | combinations fix |

### 10M events — compute (ms) (Q6 non-chunked)
| Query | baseline | stock awkward3 | + our work | our change |
|---|--:|--:|--:|---|
| Q1 | ~0 | ~0 | ~0 | — |
| Q2 | ~0 | ~0 | ~0 | — |
| Q3 | 44.4 | 88.7 (0.50×) | **1.07 (41×)** | select |
| Q4 | 15.3 | 8.5 (1.79×) | 8.5 (1.79×) | — |
| Q5 | 197335 | 2420 (82×) | **131 (1505×)** | combinations fix |
| Q6 | 213887 | 8849 (24×) | **5492 (39×)** | combinations fix |
| Q7 | 1014 | 1088 (0.93×) | **104 (9.7×)** | segmented_reduce + perm |
| Q8 | FAIL | 5503 (ak3-only) | **904** | combinations fix |

## Speedup vs baseline across scales — stock awkward3 → + our work
| Query | 100k | 1M | 10M |
|---|---|---|---|
| Q3 | 0.69× → 14× | 0.56× → 22× | 0.50× → 41× |
| Q4 | 1.11× | 1.41× | 1.79× (no change — already a segmented reduce) |
| Q5 | 0.88× → 58× | 8.6× → 337× | 82× → **1505×** |
| Q6 | 0.62× → 24× | 5.2× → 36× | 24× → 39× |
| Q7 | 0.96× → 24× | 0.91× → 11× | 0.93× → 9.7× |
| Q8 | ak3-only (base crashes) | ak3-only | ak3-only |

Two stories here:
- **Stock awkward3 already beats baseline on the combinatoric queries at scale** (Q5 8.6×@1M /
  82×@10M, Q6 5.2× / 24×) — not because its kernels are fast, but because the RawKernel backend
  explodes into hundreds of thousands of launches/syncs while cuda.compute issues ~thousands.
  At 100k it's *slower* (its per-call JIT rebuild, ~2.3 s, dominates before baseline gets large).
- **Our work removes that rebuild** (combinations fix; compute drops to flat-with-scale tens of
  ms) and **rewrites the two host-bound losers** (Q3/Q7) directly on `select`/`segmented_reduce`,
  flipping them from 0.5–0.96× to 9–41× over baseline. Q4 is unchanged (already segmented).

## End-to-end (read + load + compute + fill), 1M events — total ms

| Query | baseline | stock awkward3 | + our work |
|---|--:|--:|--:|
| Q3 | 29.3 | 36.5 (0.80×) | **20.8 (1.4×)** |
| Q5 | 19994 | 2363 (8.5×) | **103.7 (193×)** |
| Q6 | 21319 | 4131 (5.2×) | **656.6 (32×)** |
| Q7 | 267.3 | 290.2 (0.92×) | **84.6 (3.2×)** |

Q1/Q2/Q4 are ~1× across all three configs — dominated by read + fill, which the backend
doesn't change. GPU-direct cudf reads make read/load comparable across configs (load ~0.2–3 ms
vs the old pyarrow shim's ~135 ms at 10M for a flat column), so these totals are honest
end-to-end. With our work, the optimized queries become **read-bound** (Q3 ~16 of 20.8 ms is the
read; Q7 read+load ~65 of 85 ms) — compute is no longer the bottleneck.

## Takeaways for the paper
- **Robustness:** awkward3/cuda.compute runs the full ADL suite (q1–q8) at all scales. The
  baseline (2.8.11 RawKernel) still fails Q8 everywhere (genuine argmin bug). Q3's old
  failure was a **read-path artifact** and disappears with cudf — report it honestly.
- **Stock vs our work:** stock awkward3 already beats baseline on the combinatoric queries at
  scale (Q5 8.6×@1M/82×@10M, Q6 5.2×/24×) by issuing thousands of kernels instead of the
  RawKernel backend's hundreds of thousands — but loses on the host-bound light queries (Q3/Q7,
  0.5–0.96×) and pays a per-call JIT rebuild on combinations (slower than baseline at 100k). Our
  work removes the rebuild (combinations fix → Q5/Q6/Q8 up to **1505×**) and rewrites Q3/Q7 on
  `select`/`segmented_reduce` (`query3c_gpu`/`query7c_gpu`) → **9–41×**, flipping every query to
  faster than baseline. Q4 is unchanged (its hot op is already a segmented reduce, 1.1–1.8×).
- **GPU-direct reads matter end-to-end:** eliminating the host→device load stage removes a
  large, scale-dependent cost (≈135 ms at 10M for one flat column) that the old shim masked.
- **Caveats:** warm timings (JIT excluded); single GPU; one run each (no error bars). awkward3
  numbers include the combinations JIT fix. cudf is a forced-pin install (read path is libcudf
  C++; unaffected by the numba-cuda pin). A reader-dependent **fill**-stage difference exists
  (cudf's clean NumpyArray layout speeds coffea's bincount vs the shim's option-type layout) —
  it conflates read vs downstream cost; normalize layout to isolate the pure read effect.
