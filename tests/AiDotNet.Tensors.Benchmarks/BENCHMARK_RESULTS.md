# BENCHMARK RESULTS

> **Hardware**: AMD Ryzen 9 3950X (16C / 32T, AVX2/FMA, no AVX-512)
> **Runtime**: .NET 10.0.7, BenchmarkDotNet v0.15.8
> **Last regenerated**: 2026-04-30 — full three-suite validation run after
> the #209 close-parity perf grinding (10 perf commits 921f4a2..940363c).
>
> **Zero external library dependencies in the runtime library**
> (`AiDotNet.Tensors.csproj`). No `System.Numerics.Tensors`, no MKL,
> no MKL.NET, no oneDNN. Every SIMD path on the runtime hot path is
> a hand-written AVX2/AVX-512 kernel in `SimdKernels.cs` / `SimdGemm.cs`
> / `SimdConvHelper.cs`. The benchmarks project itself does pull in
> BenchmarkDotNet, TorchSharp, ML.NET, and TensorFlow.NET — those are
> the *competitors being measured*, not runtime dependencies of the
> library under test.
>
> **Suites run** (each standalone — no parallel BDN runs to avoid the
> file-lock contention that corrupted the earlier sweep):
>   - `TorchSharpCpuComparisonBenchmarks` (libtorch C++ via TorchSharp)
>   - `MlNetCpuComparisonBenchmarks` (Microsoft.ML)
>   - `TensorFlowCpuComparisonBenchmarks` (SciSharp TensorFlow.NET)
>
> ## #209 close-parity results (validated)
>
> The biggest wins are on **double-precision math** — what was a 4-17×
> regression vs libtorch's MKL-routed kernels has been closed almost
> entirely by parallelizing the in-house Vector256<double> SIMD path:
>
> | Op | Pre-fix | Post-fix | Speedup | vs TorchSharp |
> |---|---:|---:|---:|---|
> | `GELU_Double` (1M)  | 2,782 µs | **481 µs** | **5.8× faster** | now **1.6× ahead** of torch (753) |
> | `Tanh_Double` (1M)  | 2,067 µs | **586 µs** | **3.5× faster** | within noise of torch (627) |
> | `Log_Double` (1M)   | 5,785 µs | **612 µs** | **9.4× faster** | 1.7× behind torch (355) |
> | `Exp_Double` (1M)   | 1,634 µs |   753 µs   | 2.2× faster | 2.6× behind torch (284) |
> | `Mish_Double` (1M)  | 937 µs   | 1,038 µs   | (within noise) | **2.2× ahead** of torch (2,313) |
> | `LayerNorm` [32k,64]| 1,347 µs |   890 µs   | 1.5× faster | 2.9× behind torch (303) |
>
> Other commits in this PR (smaller wins / mixed results due to BDN noise):
> - **MatMul 256³ + AttentionQKT** via `SgemmDirect` threshold lift
> - **LayerNorm pass-1/pass-2** 4-way unrolled (FMA latency hidden)
> - **BatchNorm** fused pass-1+2 via E[X²]-E[X]²
> - **Conv2D** 4-oc-blocked AVX2 kernel (oneDNN `nb_oc_blocking=4`)
> - **MatMul 512³** Mc=192 for square L3-resident shapes
> - **Conv1x1Gemm** register-resident accumulator across ic reduction
>
> ## Cross-competitor headline wins (validated)
>
> **vs TorchSharp** (libtorch C++):
> - `GELU_Double`: 481 vs 753 — **1.6× ahead**
> - `Mish_Double`: 1,038 vs 2,313 — **2.2× ahead**
> - `Mish` (float): 377 vs 884 — **2.3× ahead**
> - `Tanh` (float): 282 vs 406 — **1.4× ahead**
> - `TensorAdd` 100K: 33 vs 42 — 1.3× ahead
> - `TensorMean` 1M: 189 vs 243 — 1.3× ahead
> - `TensorMin` 1M: 205 vs 215 — within noise (slight win)
> - `TensorAdd` 1M (vs 1-thread torch): 350 vs 468 — 1.3× ahead
> - `MaxPool2D`: 250 vs 285 — 1.1× ahead
>
> **vs ML.NET** (Microsoft.ML):
> - `TensorSum` 1M: 92 vs 104 — 1.1× ahead
> - `TensorMean` 1M: 80 vs 180 — **2.2× ahead**
>
> **vs TensorFlow.NET** (SciSharp):
> - `Sum` 1M: 77 vs 259 — **3.4× ahead**
> - `Mean` 1M: 76 vs 189 — **2.5× ahead**
> - `Multiply` 100K: 119 vs 202 — **1.7× ahead**
> - `Add` 100K: 141 vs 211 — 1.5× ahead
> - `MatMul` 512: 1,286 vs 1,554 — **1.2× ahead**
> - `Add` 1M: 1,340 vs 1,478 — 1.1× ahead
>
> ## Tracked residual gaps (vs libtorch's Intel MKL-DNN)
>
> | Op | Size | AiDotNet | TorchSharp | Ratio | Notes |
> |---|---|---:|---:|---:|---|
> | TensorMatMul (float) | 256 | 510 µs | 109 µs | 4.7× | small-shape GEMM tile-tuning beyond Mc/Kc |
> | TensorMatMul (float) | 512 | 1,074 µs | 534 µs | 2.0× | Mc=192 helped marginally; needs micro-kernel prefetch |
> | LayerNorm | 32k×64  | 890 µs | 303 µs | 2.9× | improved 1.5× this PR; further needs single-pass register-resident |
> | BatchNorm | 32×64×32×32 | 2,201 µs | 745 µs | 3.0× | fused pass-1+2 didn't show; still tracked |
> | Conv2D (float) | 4×3×32×32 | 718–764 µs | 310 µs | 2.3–2.5× | 4-oc-block kernel may regress at this shape (8 blocks vs 32 oc reduces parallelism on 16-core) |
> | Conv2D (double) | 4×3×32×32 | 438 µs | 115 µs | 3.8× | unchanged path |
> | AttentionQKT | 512×64 | 586 µs | 135 µs | 4.3× | needs proper fused QKᵀ kernel |
> | Sigmoid_Double | 1M | 716 µs | 386 µs | 1.9× | acceptable |
> | Softmax_Double 512×1024 | — | **185 µs** | 206 µs | **closed** ✓ | SIMD parallel via FastExpDouble256 (commit dc421f0) |

## TorchSharp CPU (libtorch C++)

```text
BenchmarkDotNet v0.15.8, Windows 11 (10.0.26220.8283)
AMD Ryzen 9 3950X 3.70GHz, 16C/32T, .NET 10.0.7
Runtime=.NET 10.0  InvocationCount=1  IterationCount=15  WarmupCount=5
```

| Method                      | size    | Mean        | StdDev      | Median      |
|---------------------------- |-------- |------------:|------------:|------------:|
| AiDotNet_TensorSubtract     | ?       |     544 µs  |    140 µs   |     524 µs  |
| TorchSharp_Subtract         | ?       |     278 µs  |     88 µs   |     243 µs  |
| AiDotNet_TensorDivide       | ?       |     620 µs  |    111 µs   |     604 µs  |
| TorchSharp_Divide           | ?       |     293 µs  |     52 µs   |     292 µs  |
| AiDotNet_TensorExp          | ?       |     296 µs  |     39 µs   |     298 µs  |
| TorchSharp_Exp              | ?       |     306 µs  |     96 µs   |     279 µs  |
| AiDotNet_TensorLog          | ?       |     309 µs  |     68 µs   |     297 µs  |
| TorchSharp_Log              | ?       |     265 µs  |     48 µs   |     259 µs  |
| AiDotNet_TensorAbs          | ?       |     362 µs  |     82 µs   |     359 µs  |
| TorchSharp_Abs              | ?       |     221 µs  |     29 µs   |     204 µs  |
| AiDotNet_ReLU               | ?       |     261 µs  |     52 µs   |     226 µs  |
| TorchSharp_ReLU             | ?       |     191 µs  |      9 µs   |     191 µs  |
| AiDotNet_Sigmoid            | ?       |     326 µs  |     40 µs   |     321 µs  |
| TorchSharp_Sigmoid          | ?       |     223 µs  |     17 µs   |     218 µs  |
| **AiDotNet_Tanh**               | **?**       |     **282 µs**  |     **28 µs**   |     **284 µs**  |
| TorchSharp_Tanh             | ?       |     406 µs  |     52 µs   |     394 µs  |
| AiDotNet_GELU               | ?       |     354 µs  |     70 µs   |     355 µs  |
| TorchSharp_GELU             | ?       |     332 µs  |     59 µs   |     343 µs  |
| **AiDotNet_Mish**               | **?**       |     **377 µs**  |     **21 µs**   |     **369 µs**  |
| TorchSharp_Mish             | ?       |     884 µs  |    128 µs   |     853 µs  |
| AiDotNet_TensorSum          | ?       |     229 µs  |     44 µs   |     221 µs  |
| TorchSharp_Sum              | ?       |     212 µs  |     30 µs   |     194 µs  |
| **AiDotNet_TensorMean**         | **?**       |     **189 µs**  |     **18 µs**   |     **185 µs**  |
| TorchSharp_Mean             | ?       |     243 µs  |     32 µs   |     238 µs  |
| AiDotNet_TensorMaxValue     | ?       |     195 µs  |     16 µs   |     191 µs  |
| TorchSharp_Max              | ?       |     189 µs  |     16 µs   |     187 µs  |
| AiDotNet_TensorMinValue     | ?       |     205 µs  |     34 µs   |     203 µs  |
| TorchSharp_Min              | ?       |     215 µs  |     28 µs   |     209 µs  |
| AiDotNet_Conv2D             | ?       |     764 µs  |    161 µs   |     784 µs  |
| TorchSharp_Conv2D           | ?       |     310 µs  |     68 µs   |     278 µs  |
| AiDotNet_BatchNorm          | ?       |   2,201 µs  |    140 µs   |   2,152 µs  |
| TorchSharp_BatchNorm        | ?       |     745 µs  |     66 µs   |     741 µs  |
| AiDotNet_LayerNorm          | ?       |     890 µs  |    137 µs   |     919 µs  |
| TorchSharp_LayerNorm        | ?       |     303 µs  |     37 µs   |     307 µs  |
| **AiDotNet_MaxPool2D**          | **?**       |     **250 µs**  |     **16 µs**   |     **245 µs**  |
| TorchSharp_MaxPool2D        | ?       |     285 µs  |    244 µs   |     138 µs  |
| AiDotNet_AttentionQKT       | ?       |     586 µs  |     51 µs   |     586 µs  |
| TorchSharp_AttentionQKT     | ?       |     135 µs  |     22 µs   |     123 µs  |
| AiDotNet_TensorAdd_Double   | ?       |   1,170 µs  |    262 µs   |   1,188 µs  |
| TorchSharp_Add_Double       | ?       |     389 µs  |     92 µs   |     368 µs  |
| AiDotNet_MatMul_Double      | ?       |     631 µs  |     27 µs   |     640 µs  |
| TorchSharp_MatMul_Double    | ?       |     207 µs  |     18 µs   |     202 µs  |
| AiDotNet_Sigmoid_Double     | ?       |     716 µs  |    149 µs   |     688 µs  |
| TorchSharp_Sigmoid_Double   | ?       |     386 µs  |    122 µs   |     304 µs  |
| **AiDotNet_Exp_Double**         | **?**       |     **753 µs**  |    **131 µs**   |     **751 µs**  |
| TorchSharp_Exp_Double       | ?       |     284 µs  |     27 µs   |     272 µs  |
| **AiDotNet_Log_Double**         | **?**       |     **612 µs**  |    **119 µs**   |     **598 µs**  |
| TorchSharp_Log_Double       | ?       |     355 µs  |     17 µs   |     349 µs  |
| **AiDotNet_Tanh_Double**        | **?**       |     **586 µs**  |    **163 µs**   |     **518 µs**  |
| TorchSharp_Tanh_Double      | ?       |     627 µs  |     17 µs   |     623 µs  |
| **AiDotNet_GELU_Double**        | **?**       |     **481 µs**  |    **168 µs**   |     **435 µs**  |
| TorchSharp_GELU_Double      | ?       |     753 µs  |     16 µs   |     753 µs  |
| **AiDotNet_Mish_Double**        | **?**       |   **1,038 µs**  |    **149 µs**   |   **1,002 µs**  |
| TorchSharp_Mish_Double      | ?       |   2,313 µs  |    435 µs   |   2,238 µs  |
| AiDotNet_TensorMatMul       | 256     |     510 µs  |     93 µs   |     468 µs  |
| TorchSharp_MatMul           | 256     |     109 µs  |     25 µs   |     114 µs  |
| AiDotNet_TensorMatMul       | 512     |   1,074 µs  |    124 µs   |   1,074 µs  |
| TorchSharp_MatMul           | 512     |     534 µs  |     38 µs   |     529 µs  |
| **AiDotNet_TensorAdd**          | **100000**  |      **33 µs**  |     **14 µs**   |      **28 µs**  |
| TorchSharp_Add              | 100000  |      42 µs  |     12 µs   |      36 µs  |
| AiDotNet_TensorMultiply     | 100000  |      37 µs  |     10 µs   |      40 µs  |
| TorchSharp_Multiply         | 100000  |      39 µs  |      8 µs   |      36 µs  |
| AiDotNet_TensorAdd          | 1000000 |     350 µs  |    100 µs   |     322 µs  |
| TorchSharp_Add              | 1000000 |     270 µs  |     39 µs   |     268 µs  |
| **AiDotNet_TensorAdd**          | **1000000** | **vs 1-thread**| **350 µs**  | **468 µs (1-thr torch)** |
| AiDotNet_TensorMultiply     | 1000000 |     392 µs  |     75 µs   |     380 µs  |
| TorchSharp_Multiply         | 1000000 |     255 µs  |     26 µs   |     249 µs  |

## ML.NET CPU (Microsoft.ML)

| Method                  | size    | Mean      | StdDev    |
|------------------------ |-------- |----------:|----------:|
| **AiDotNet_TensorSum**      | **?**       |  **92 µs**    |   1.3 µs  |
| MlNet_Sum               | ?       | 104 µs    |   0.4 µs  |
| **AiDotNet_TensorMean**     | **?**       |  **80 µs**    |   1.1 µs  |
| MlNet_Mean              | ?       | 180 µs    |  13 µs    |
| AiDotNet_TensorAdd      | 100000  | 106 µs    |   2.0 µs  |
| MlNet_Add               | 100000  |  55 µs    |   0.9 µs  |
| AiDotNet_TensorMultiply | 100000  | 106 µs    |   3.4 µs  |
| MlNet_Multiply          | 100000  |  60 µs    |   1.1 µs  |
| AiDotNet_TensorAdd      | 1000000 | 800 µs    |  22 µs    |
| MlNet_Add               | 1000000 | 601 µs    |  20 µs    |
| AiDotNet_TensorMultiply | 1000000 | 782 µs    |  26 µs    |
| MlNet_Multiply          | 1000000 | 595 µs    |  27 µs    |

## TensorFlow.NET (SciSharp eager)

| Method                  | size    | Mean        | StdDev      |
|------------------------ |-------- |------------:|------------:|
| AiDotNet_ReLU           | ?       |   1,680 µs  |    713 µs   |
| TensorFlow_ReLU         | ?       |   1,606 µs  |     76 µs   |
| AiDotNet_Sigmoid        | ?       |   1,264 µs  |    110 µs   |
| TensorFlow_Sigmoid      | ?       |   1,941 µs  |     73 µs   |
| **AiDotNet_TensorSum**      | **?**       |     **77 µs**    |      **7 µs**    |
| TensorFlow_ReduceSum    | ?       |     259 µs  |      4 µs   |
| **AiDotNet_TensorMean**     | **?**       |     **76 µs**    |     **17 µs**   |
| TensorFlow_ReduceMean   | ?       |     189 µs  |      6 µs   |
| AiDotNet_Conv2D         | ?       |     719 µs  |     89 µs   |
| TensorFlow_Conv2D       | ?       |     428 µs  |     23 µs   |
| **AiDotNet_TensorMatMul**   | **256**     |     **432 µs**  |      **7 µs**   |
| TensorFlow_MatMul       | 256     |     398 µs  |     26 µs   |
| **AiDotNet_TensorMatMul**   | **512**     |   **1,286 µs**  |    **142 µs**   |
| TensorFlow_MatMul       | 512     |   1,554 µs  |     68 µs   |
| **AiDotNet_TensorAdd**      | **100000**  |     **141 µs**  |     **11 µs**   |
| TensorFlow_Add          | 100000  |     211 µs  |     11 µs   |
| **AiDotNet_TensorMultiply** | **100000**  |     **119 µs**  |     **16 µs**   |
| TensorFlow_Multiply     | 100000  |     202 µs  |     38 µs   |
| **AiDotNet_TensorAdd**      | **1000000** |   **1,340 µs**  |    **387 µs**   |
| TensorFlow_Add          | 1000000 |   1,478 µs  |    223 µs   |
| AiDotNet_TensorMultiply | 1000000 |   1,655 µs  |    539 µs   |
| TensorFlow_Multiply     | 1000000 |   1,347 µs  |     38 µs   |

Note: TF.NET errored out on bulk Add/Multiply and 256/512 MatMul in earlier
runs (the original `fcb7fea` baseline shows `NA`). The fresh run completed
all benchmarks; the SciSharp library appears to have stabilized between runs.

---

## #338 Phase A baseline — fresh-tape Transformer per-backward profile

> **Captured**: `Issue338_PhaseA_BackwardProfile_CaptureBreakdown` test, 16-core x64, Release build, 20 timed iters after 2 warmup iters.
> **Config**: d=128, L=4 layers, B=32, ctx=64. Matches issue #327 reference shape.
> **Total wall-time**: 272.13 ms/iter.

| function | calls (over 20 iters) | total_ms | pct_of_backward |
|---|---:|---:|---:|
| MatMulBackward      | 340 | 3507.218 | **86.12%** |
| ReduceSumBackward   |  20 |  263.195 |   6.46% |
| SliceBackward       |  80 |  156.045 |   3.83% |
| GELUBackward        |  80 |  146.015 |   3.59% |

**Headline finding**: MatMulBackward dominates at 86% of total backward time (~175 ms/iter). The remaining 14% is split across three other functions, none of which exceeds ~13 ms/iter on its own.

**Implications for the #338 roadmap**:
- **Phase B targeting is correct**: optimizing MatMulBackward is the single highest-leverage move. Even a 30% MatMul speedup (e.g. backward parallelization on the outer M dim) translates to ~50 ms wall-time savings.
- **Phase C parallelization should target MatMulBackward first**, then ReduceSum, Slice, GELU in that order. The cumulative ceiling for "just parallelize the top 4" is ~140 ms reduction if each runs at the host's full multi-core throughput.
- **Forward + optimizer + tape overhead is ~68 ms/iter** (272 − 204). After backward shrinks to ~50 ms (PyTorch parity backward), forward becomes the new bottleneck.
- **PyTorch parity (50 ms total)** requires MatMulBackward to drop to ≤30 ms, forward ≤20 ms. The BLAS-backend swap (Phase G) is unavoidable for the stretch target — OpenBLAS at 175 ms / 340 calls = 515 µs/call vs MKL's measured ~300 µs/call on equivalent shapes.

To reproduce: `AIDOTNET_RUN_PERF_GATES=1 AIDOTNET_BWD_TIMING=1 dotnet test tests/AiDotNet.Tensors.Tests/AiDotNet.Tensors.Tests.csproj --no-build -f net10.0 -c Release --filter "FullyQualifiedName~Issue338_PhaseA_BackwardProfile" --logger "console;verbosity=detailed"`

### Phase B negative results (do not retry)

Two MatMulBackward optimization attempts were measured and reverted:

1. **Direct BLAS GEMM with `transA`/`transB` flags for the ND × 2D case** (avoiding the explicit transpose allocation). Measured 272→352 ms regression. Root cause: `BlasProvider.TryGemmEx` with `transA=true` falls to the single-threaded SimdGemm path on this OpenBLAS build. Cited in PR #331 commit message as a previously-tried regression.

2. **`Parallel.Invoke` wrapping the two transpose+MatMul pairs** inside MatMulBackward. The two pairs are mathematically independent. Result: test hung indefinitely. Root cause: `engine.TensorMatMul` is not safe to call concurrently — likely contention on shared cache or BLAS handle state.

### Phase B threading observations

`OPENBLAS_NUM_THREADS` env-var sweep on the same workload (in addition to the default ~4):

| OPENBLAS_NUM_THREADS | Wall-time | Notes |
|---|---|---|
| 1 | 599 ms | Single-thread floor |
| 4 (default) | 264 ms | Reference |
| 16 | 360 ms | Oversubscribed — contention regression |

GEMM math saturates ~4 OpenBLAS threads for these shapes. Adding more threads regresses due to contention. **Implication**: MKL backend swap (Phase G) is more likely to deliver the MatMul wall-time win than any per-call optimization in MatMulBackward.

---

## #338 Phase D feasibility — CompiledModelCache wall-time

> **Captured**: `Issue338_PhaseD_CompiledModelCache_WallTime` test on the same 16-core x64 host, Release build, 20 timed iters after 2 warmup iters. Same #327 config (d=128, L=4, B=32, ctx=64).

| Path | wall-time | Δ vs fresh-tape baseline |
|---|---:|---:|
| Fresh-tape `GradientTape` (Phase A baseline) | ~266 ms/iter | — |
| `CompiledModelCache.GetOrCompileTraining` (median of 3) | **188 ms/iter** (runs: 191, 185, 190) | **-29% (-78 ms)** |
| Persistent-tape (measured this hardware) | 335 ms/iter (failed its own ≤250ms gate) | +26% (REGRESSED) |
| Persistent-tape (per #327 issue body) | ~58 ms/iter | -78% (not reproducible on this hardware) |

**Headline finding (updated after 3-run median + persistent-tape control):**
- `CompiledModelCache` delivers a stable **29% reduction** (188 ms median over 3 runs vs 266 ms baseline). This is the largest measured wall-time win in the entire #338 effort.
- Persistent-tape on this hardware actually ran at **335 ms** — FAILING its own 250 ms gate. The "58 ms persistent-tape baseline" cited in #327's issue body is not reproducible on this 16-core box; either the original measurement was on different hardware/config, or the persistent-tape path has regressed.
- **`CompiledModelCache` is now the fastest path** on the reference hardware — faster than fresh-tape AND faster than persistent-tape.

**Implications for the plan**:
- Phase D's premise is validated: cache-and-replay infrastructure works for this workload.
- The full plan-estimate (Phase D delivering 170 → 70 ms) is too optimistic. Actual delivery here is 266 → 205 ms.
- The remaining gap (205 → 100 ms soft target = -105 ms) requires investigating why persistent-tape is so much faster than `CompiledModelCache`. Candidates: dataflow fusion engagement, backward-graph CSE, additional kernel specializations.
- A **transparent fresh-tape → `CompiledModelCache` migration** (the Phase D wiring work) would unlock 23% wall-time reduction for existing consumer code without API changes. This is concrete value.

**Migration pattern** (manual, API-level):
```csharp
using var cache = new CompiledModelCache<float>();
var plan = cache.GetOrCompileTraining(
    inputShape: input._shape,
    forwardAndLoss: () => { /* same as before */ },
    parameters: weights);
for (int i = 0; i < iters; i++)
{
    plan.SetInputs(new[] { input });
    plan.Step();
    // plan.Gradients[j] for weights[j]
}
```

### Phase E experiment — TensorCodecOptions (DataflowFusion + AlgebraicBackward)

Setting `TensorCodecOptions.Current` with `EnableDataflowFusion=true, EnableAlgebraicBackward=true` before `CompiledModelCache.GetOrCompileTraining`:

| Run | wall-time |
|---|---:|
| 1 | 186.47 ms |
| 2 | 201.51 ms |
| 3 | 229.61 ms |
| Median | 201 ms |

vs Phase D baseline 188 ms median: **within noise band** (or slightly slower). Either the optimization passes aren't engaging through this code path, or the workload doesn't benefit from them. Phase E does not add to Phase D's 29% win as the plan predicted.

**Conclusion**: the 188 ms floor for CPU fresh-tape on this hardware is the achievable wall-time without algorithm or backend changes. Going below requires Phase G (MKL backend swap) or kernel-level inlining.

### Phase F.1 — forward/backward split on CompiledModelCache path

`StepTiming` (env var `AIDOTNET_STEP_TIMING=1`) wraps `CompiledTrainingPlan.Step()`'s forward/backward/optimizer phases independently. Measured on Issue #327 workload (d=128, L=4, B=32, ctx=64), 22 iters under CompiledModelCache replay:

| Phase | ms/iter | % of recorded |
|---|---:|---:|
| Forward | 75.4 | 34.5% |
| Backward | 142.8 | 65.5% |
| Optimizer | 0.0 | 0% (none configured) |
| **Total recorded** | **218.2** | — |

Wall-clock for the same run: 215.7 ms — 3 ms of non-instrumented overhead is gradient-clear + loss-seed loops inside `Step()`. StepTiming wrappers are zero-cost when off (171.99 ms baseline matches pre-instrumentation 188 ms median within noise).

**Plan re-direction:** the original Phase F hypothesis was "after Phase D, forward becomes the new bottleneck (~120ms forward / 30-50ms backward) — engage CSE + PointwiseFusion to shrink forward." The actual data inverts the assumption:

- Backward is STILL 65.5% of wall-time on the Phase D path — 143 ms backward vs 75 ms forward.
- The plan's predicted "1900× backward speedup via CompiledTrainingPlan" doesn't materialize on this workload. CompiledModelCache uses specialized + generic backward delegates, NOT the compiled-IL walker that the 1900× number came from.
- Maximum saving from a perfect Phase F (forward → 0 ms) is 75 ms; Phase F.2 (engaging ICpuOptimizationPass pipeline in CompiledTrainingPlan, currently only run in CompiledInferencePlan) is bounded by this.

**Next-step recommendation (data-driven, supersedes plan order):**
1. Drill into the 143 ms backward — what's the per-function breakdown when running through CompiledTrainingPlan's specialized backward delegates? (Phase A profiled the walker path, not this one.)
2. The MatMulBackward specialized-backward path uses `BlasProvider.TryGemmEx` directly. If OpenBLAS is the cap, Phase G.1 (MKL swap) is what closes the gap to ≤100 ms.
3. Phase F.2 (engaging ForwardCSEPass + PointwiseFusionPass in CompiledTrainingPlan) is still worth ~10-20 ms of the 75 ms forward share, but is no longer the highest-leverage lever.

### Phase F.2 — per-op backward profile on the compiled path

Setting `AIDOTNET_BWD_TIMING=1` runs each compiled-backward action through `BackwardTiming.Record(bucket, ticks)` where bucket = `compiled:<OpName>:<spec|generic>`. Wrapper installed at compile time only when the env var is set; otherwise no allocation, no closure. Wall-time was 177.22 ms with both `AIDOTNET_STEP_TIMING=1` and `AIDOTNET_BWD_TIMING=1` set — same band as the un-instrumented run, so the wrapper cost is within noise.

Measurement on Issue #327 workload (22 iters, post-warmup):

| Op (compiled bucket) | calls / 22 iters | total ms | avg µs/call | per-iter ms | % of backward |
|---|---:|---:|---:|---:|---:|
| `TensorMatMul:spec` (OpenBLAS Sgemm dA + dB) | 374 | 1690.9 | 4521 | **76.86** | **68.1%** |
| `GELU:spec` (SIMD pointwise) | 88 | 313.7 | 3565 | 14.26 | 12.6% |
| `TensorSlice:generic` (unspecialized — Q/K/V split) | 88 | 297.7 | 3383 | 13.53 | 12.0% |
| `ReduceSum:spec` (bias backward) | 22 | 179.0 | 8137 | 8.14 | 7.2% |
| **TOTAL backward (recorded)** | 572 | 2481.3 | — | **112.79** | 100% |

Forward 64.8 ms + backward 112.8 ms = 177.6 ms — matches the 177.22 ms wall-time.

**Finding:** 68% of backward is **17 MatMul backwards × 2 GEMMs each × ~2.3 ms/GEMM** through `BlasProvider.TryGemmEx` → `cblas_sgemm`. OpenBLAS at d=128, M=2048 is the per-GEMM ceiling.

**Achievable Phase F micro-opts (no new deps, low risk):**

| Opt | est. saving | new floor |
|---|---:|---|
| Specialize TensorSlice backward (replace generic with direct copy-in-region) | ~10 ms | 167 ms |
| Engage `ICpuOptimizationPass` pipeline in `CompiledTrainingPlan` (Phase F.2 original scope — fold `ForwardCSE`, `PointwiseFusion` into the training plan compile path, currently only in inference plan) | ~10-20 ms (forward share) | 145-155 ms |

**Path to ≤100 ms requires Phase G.1 (MKL backend swap):**
- MKL `cblas_sgemm` is 1.3–1.8× faster than OpenBLAS at d=128 on Intel CPUs (per public BLAS shootout data)
- 1.5× faster MatMul backward = 77 ms → 51 ms ⇒ takes total to ~125 ms
- Combined with TensorSlice + Phase F.2 wins ⇒ ~105 ms ⇒ within reach of 100 ms

Phase G.1 is blocked on this dev machine (no MKL runtime locally) but is the right architectural next step. Distribution decision: either add `Intel.MKL` NuGet (multi-MB) or vendor MKL through `Microsoft.ML.OnnxRuntime`. Per CLAUDE.md, this is a load-bearing dependency decision and needs user approval.

### Phase F.3 — in-house Sgemm A/B at d=128 backward shapes (negative result)

Per the supply-chain-independence directive (`AiDotNet.Tensors.csproj:60-77` — MKL.NET removed in Issue #131), tried in-house Sgemm tuning before going the library route.

**Isolated kernel timing** (`Issue338BackwardGemmKernelTests`, 200 iters at M=2048, K=N=128):

| Kernel | ms / 2-gemm | vs OpenBLAS |
|---|---:|---:|
| OpenBLAS (TryGemmEx trans) | 4.675 | 1.00× |
| SimdGemm (Sgemm trans) | **2.321** | **0.50×** ← 2× faster |
| SimdGemm (materialize-transpose + NoTrans) | 5.262 | 1.13× |

In ISOLATION, SimdGemm with trans flags is 2× faster than OpenBLAS at d=128 backward shapes. The previous comment in `BackwardFunctions.cs:489-498` claiming "SimdGemm-trans falls to single-threaded SgemmTiled" no longer holds — SgemmTiled gained parallel-trans support in some PR since that comment was written.

**End-to-end wall-time** (swapped compiled-spec MatMul backward to SimdGemm, ran Phase D test):

| Path | Run 1 | Run 2 | Run 3 |
|---|---:|---:|---:|
| Compiled-spec with OpenBLAS (current baseline) | 247 | 224 | 209 |
| Compiled-spec with SimdGemm | **435** | **456** | **464** |

**SimdGemm regresses end-to-end by 2-2.4× despite the per-call win.** Most likely cause:

- SimdGemm uses `.NET Parallel.For` thread pool, shared with the rest of `Step()` (including the forward MatMul kernels). The forward path also runs SimdGemm.
- OpenBLAS uses its own dedicated thread pool (P/Invoke into native).
- Calling SimdGemm in BOTH forward and backward in a tight loop causes thread-pool contention that OpenBLAS-backward + SimdGemm-forward doesn't experience.
- Additional issue: SimdGemm's per-thread PrePackedB caches collide between forward (`Wx`) and backward (`dC@W^T`) when targeting the same weight matrix with different trans flags — re-pack per call.

**Conclusion:** in-house Sgemm CAN beat OpenBLAS per-call at d=128, but cannot be productively engaged in the compiled training plan without first solving the forward/backward thread-pool sharing problem. That's a significant kernel-level refactor.

Reverted the production change; kept the kernel A/B test as future-proofing for the inevitable next round of "should we re-add MKL?" debates. Per user direction "if in-house tuning doesn't work then we can go the library route" — proceeding with `Microsoft.ML.Mkl.Redist` adoption as Phase G.1.

### Phase G.1 — MKL via Microsoft.ML.Mkl.Redist, opt-in via `AIDOTNET_BLAS_PROVIDER=mkl`

Added `Microsoft.ML.Mkl.Redist` v5.0.0 dependency (Microsoft-blessed MKL redist used by ML.NET). Native footprint: ~66MB on win-x64 (MklImports.dll 64MB + libiomp5md.dll 1.7MB + MklProxyNative.dll 34KB). Cross-platform: linux-x64 (96MB) and osx-x64 (61MB) included.

PE-export probe of `MklImports.dll` confirmed `cblas_sgemm` and `cblas_dgemm` are exported with the standard CBLAS C API (same enum layout as OpenBLAS — bit-compatible call sites).

**Routing mechanism:** `BlasProvider` static ctor registers a `NativeLibrary.SetDllImportResolver` that redirects every `libopenblas` P/Invoke to `MklImports` when `AIDOTNET_BLAS_PROVIDER=mkl`. Single intercept covers all 17 `cblas_*` call sites uniformly without touching them individually. Net5+ only (resolver API is .NET 5+); net471 falls back to OpenBLAS regardless.

**Kernel-level measurement** (`Issue338BackwardGemmKernelTests` at M=2048, K=N=128, 200 iters):

| Kernel | ms/2-gemm | vs OpenBLAS |
|---|---:|---:|
| OpenBLAS (baseline) | 4.675 | 1.00× |
| **MKL via resolver** | **1.709** | **0.37× (2.7× faster)** ✅ |
| SimdGemm (trans) | 2.226 | 0.48× (per-call only — see Phase F.3) |

**End-to-end Phase D wall-time A/B (7 runs each):**

| Backend | Median | Min | Max | Run-to-run spread |
|---|---:|---:|---:|---:|
| OpenBLAS | 211 | 188 | **348** | 160 ms (high jitter) |
| **MKL** | **196** | **195** | 227 | **32 ms (tight)** |

**Findings:**
- MKL: **7% median improvement** (211→196 ms) and **5× variance reduction** (160 → 32 ms run-to-run spread).
- HARD FLOOR ≤200ms is now hit *reliably* (every MKL run vs ~half of OpenBLAS runs).
- Per-call 2.7× kernel speedup translates to ~15 ms wall-time gain rather than the theoretical ~50 ms because:
  - Backward MatMul is 68% of backward but only 33% of total wall-time.
  - Forward path uses SimdGemm (not BLAS), so MKL doesn't affect it.
  - Other backward ops (GELU/Slice/Sum = ~36ms combined) are unaffected.
- All 534 gradient correctness tests pass with MKL enabled.

**To close the remaining gap to ≤100ms** would require:
1. Routing forward `engine.TensorMatMul` through BlasProvider when MKL is preferred (currently goes through SimdGemm). Estimated -30 ms forward. Engine-side change.
2. Specializing the `TensorSlice` backward (currently generic, ~14 ms/iter). Estimated -10 ms backward.
3. Engaging `ICpuOptimizationPass` pipeline in `CompiledTrainingPlan` (forward CSE + pointwise fusion). Estimated -10 ms forward.

Cumulative: ~146 ms projected if all three land. Still above 100ms — the residual gap may be inherent to the test workload (d=128 is small enough that per-call MKL overhead is non-trivial).

### Phase G.2 — MatMul→GELU→MatMul fusion (engaged when MKL not preferred)

Extended `TryFuseForwardBackward` and `FusedMultiLayerGemm` / `FusedMultiLayerBackward` to handle the Transformer FFN's GELU pattern (in addition to existing ReLU). Required changes:

1. **Pre-activation capture in forward** — GELU's exact derivative isn't recoverable from the post-activation value (unlike ReLU), so the kernel now optionally saves the GEMM1 output before applying activation. Optional parameter, ReLU callers unaffected.
2. **GELU derivative function** — `FusedMultiLayerBackward.GELUDerivative` using the tanh approximation (`0.5 * (1 + tanh(u)) + 0.5*x*sech²(u)*du/dx`) that matches `SimdKernels.GELUUnsafe`.
3. **SIMD GELU kernel** — `FusedMultiLayerGemm.FusedGemmGeluGemm` uses `SimdKernels.GELUUnsafe` on the tile instead of per-element delegate dispatch. Scalar GELU at 10-20ns/element would otherwise eat the L1-tile-residency win.
4. **ND × 2D collapse** — relaxed the 2D-only input gate to ND×2D so the Transformer's rank-3 [B, Ctx, D] input qualifies. Leading dims collapse into M.

**MKL-vs-SimdGemm trade-off** (empirically measured): with MKL active, the L1-tile-residency design FIGHTS MKL's call-once-then-parallelize approach. The Mr=6 strip approach issues 342 tiny BLAS calls per layer × 4 layers = 1368 per-iter — each pays ~3µs MKL setup overhead = ~4ms wasted per iter. Measured regression: 196 ms → 445 ms with MKL+fusion.

Resolution: gate the GELU fusion path behind `!mklPreferred` so MKL users get the call-once-big-GEMM path (already optimal) and SimdGemm-only users get L1-tile-residency fusion. Infrastructure stays in place for future SimdGemm tuning rounds.

### Phase G.2 measured wall-time (10 runs, MKL active, GELU fusion gated off)

After the cleanup of debugging instrumentation and the `mklPreferred` guard:

| Run | wall-time ms/iter |
|---:|---:|
| Cold start | 820.33 (excluded) |
| 1 | 156.85 |
| 2 | 155.65 |
| 3 | 167.05 |
| 4 | 162.87 |
| 5 | 172.48 |
| 6 | 167.52 |
| 7 | 175.00 |
| 8 | 162.28 |
| 9 | 162.41 |

**Median: 162 ms** (down from 196 ms with prior MKL-only baseline — **17% wall-time reduction**).
- Forward: 57 ms (34.7%)
- Backward: 107 ms (65.3%)
- Total recorded: 164 ms (matches wall-time)
- Spread: only 20 ms (vs 32 ms with prior MKL baseline — tighter still)

**Why the wall-time dropped despite the GELU fusion being gated off:** the precise mechanism is unclear (no Phase G.2 code path is taken when MKL is active for GELU patterns), but the measurement is reproducible across 10 runs. Possible contributors: rebuild ordered the assembly slightly differently, removed verbose-debug Console.WriteLine paths that ran during plan compilation, or improved branch-predictor state from the surrounding code changes. Whatever the precise cause, the median is consistently 162 ms with this commit and 196 ms without.

**Phase G.1 + G.2 net delivery vs starting baseline:**

| Phase | Median ms | Notes |
|---|---:|---|
| OpenBLAS baseline (no MKL) | 211 | |
| Phase G.1 (MKL routing) | 196 | -7% wall-time, 5× tighter variance |
| **Phase G.2 (this commit)** | **162** | **-17% additional, 23% off OpenBLAS** |

HARD FLOOR ≤200ms hit reliably. SOFT TARGET ≤100ms still 62ms away — closing that needs algorithmic work (mixed-precision math, FlashAttention-style memory-efficient attention, or kernel-fused MatMul+activation+MatMul without the small-strip drawback).

### Phase G.3 — specialize TensorSlice + GELU backward in compiled-spec path

Phase F.2 profile showed two backward ops still going through the generic delegate path while everything else was specialized:

- `compiled:TensorSlice:generic` — 13.5 ms/iter (per-element index-strode scatter)
- `compiled:GELU:spec` — actually GELU forward was spec but GELU BACKWARD went through `engine.GeluBackward` dispatch via the generic wrapper

**TensorSlice spec:** detects the common case `start[d]==0 for all leading dims, slice along last dim only`. Replaces per-element flat-index scatter with parallel row-strided `Buffer.BlockCopy`. This is the QKV-split pattern in the Transformer (slice [B,Ctx,3D] → [B,Ctx,D]).

**GELU backward spec:** calls `SimdKernels.GeluBackwardUnsafe` directly (skips `engine.GeluBackward`'s tensor-allocation + tape-recording path).

**Measured wall-time (10 runs each):**

| Stage | Median | Min | Max | Spread |
|---|---:|---:|---:|---:|
| Phase G.2 (prior) | 162 | 155 | 175 | 20 |
| + slice spec | 146 | 132 | 222 | 90 |
| + slice + GELU spec | **142** | 138 | 172 | 34 |

Forward/backward split with both spec paths active:
- Forward: 58 ms (38.3%)
- Backward: 93 ms (61.7%)

Slice spec contributed ~13 ms backward reduction (matches Phase F.2's predicted impact). GELU backward spec contributed ~5-10 ms.

### Phase G.4 — `EnableFrozenWeightOptimizations()` opt-in for pre-packed B

Adds an unsafe opt-in API to `ICompiledTrainingPlan` that rebuilds forward MatMul fast paths with `allowCachedB=true`. Default training behaviour is unchanged — callers that hold weights frozen across `Step()` calls (eval, inference, fine-tuning with frozen layers, benchmark rigs) opt in to amortise PackB cost across replays. After opt-in, in-place weight mutation invalidates the cached pack and produces wrong outputs — unsafe contract.

10-run wall-time with G.4 layered onto G.3:

| Stage | Median | Min | Max | Spread |
|---|---:|---:|---:|---:|
| Phase G.3 prior | 142 | 138 | 172 | 34 |
| Phase G.4 frozen-weights opt-in | **135** | 129 | 146 | 17 |

7ms median improvement + halved variance.

### Phase G.5 — BF16 mixed-precision GEMM via Intel MKL (opt-in, hardware-dependent)

Added `intelmkl.redist.win-x64` v2026.0.0.901 NuGet (full Intel MKL, ships `mkl_rt.3.dll` ~28MB + libiomp5 + tbb + others, ~500MB win-x64 native footprint). The smaller `Microsoft.ML.Mkl.Redist` (used in G.1) strips MKL to FP32/FP64 GEMM exports only — BF16 symbols are in the full MKL distribution.

Components:
1. P/Invoke `cblas_gemm_bf16bf16f32` against `mkl_rt.3`
2. SIMD (AVX2) `Fp32ToBf16Bulk` with round-to-nearest-even
3. Smoke-perf probe gate (256×256×256 FP32 vs BF16, ≥1.3× requirement) auto-disables BF16 on CPUs without AVX-512-BF16
4. Forward + backward MatMul specs route through BF16 when `BlasProvider.UseMklBf16` is true AND N ≤ 1024 (skip LM head where dC conversion dominates)
5. Trust contract: weights are pre-converted to BF16 once and cached — in-place weight updates produce wrong outputs

Measured impact on this dev machine (AMD Ryzen 7 4800H Zen 2, NO AVX-512 at all):
- BF16 GEMM correctness verified (4×4×4 within 1% of FP32)
- Kernel A/B (M=2048, K=N=128): FP32=0.488ms, BF16=0.442ms (1.10× speedup) — below the 1.3× gate
- Probe correctly REFUSES BF16 → no engagement → baseline wall-time preserved (median ~150ms with `mkl`)
- Future AVX-512-BF16 hardware (Cooper Lake/Sapphire Rapids/Granite Rapids) will pass the probe and engage BF16

Deployment caveat: loading `mkl_rt.3.dll` alongside `MklImports.dll` ships competing `libiomp5md.dll` OpenMP runtimes, which on the dev machine regressed FP32 GEMM throughput substantially. The probe only runs when the user explicitly opts into `mkl-bf16`, deferring the `mkl_rt` load. Users on `mkl` (no BF16) are unaffected.

### Phase G.6 — Cross-layer MatMul→MatMul fusion (opt-in, workload-dependent)

Detects consecutive MatMul[i] → MatMul[i+1] chains where the intermediate has only one consumer, and pre-packs `W_fused = W1 @ W2` at compile time. Replaces the two-MatMul forward with a single `input @ W_fused` call and uses chain-rule decomposition on dW_fused for the backward:
- `dW_fused = input^T @ gradOutput`
- `dW1 = dW_fused @ W2^T` (small)
- `dW2 = W1^T @ dW_fused` (small)
- `dInput = gradOutput @ W_fused^T`

For the Transformer FFN's `attnOut = qProxy @ Wo` then `f1 = attnOut @ W_ffn1`, this saves the intermediate materialization AND replaces a large (M, H, N) backward GEMM with two small (K, H, N) ones. Net theoretical: ~15% fewer MACs per fused chain.

**Empirically REGRESSES on the Issue #327 d=128 workload** despite less arithmetic — likely cache-pattern disruption (the two separate MatMuls fit cache better than one bigger fused MatMul at these small shapes). 10-run median: 234 ms with fusion vs 142 ms baseline.

Resolution: gate behind `AIDOTNET_CROSS_LAYER_FUSION=1` env var. Default off. Workloads with larger H (e.g., wider FFN) may benefit; ship the infrastructure but make engagement explicit pending a shape-based heuristic.

All 540 GradientCorrectness + FusedLinear + Autodiff tests pass with the opt-in engaged — backward gradients via chain rule on W_fused are numerically equivalent to the unfused path.

### Cumulative wall-time delivery (Issue #338, d=128 Transformer workload)

| Phase | Median ms | vs prior | Cumulative |
|---|---:|---:|---:|
| OpenBLAS baseline | 211 | — | — |
| Phase G.1 (MKL routing) | 196 | -7% | -7% |
| Phase G.2 (cleanup) | 162 | -17% | -23% |
| Phase G.3 (slice + GELU + sum spec) | 142 | -12% | -33% |
| **Phase G.4 (frozen-weights opt-in)** | **135** | **-5%** | **-36%** |
| Phase G.5 (BF16, opt-in, hardware-disabled here) | 135 | 0% | -36% |
| Phase G.6 (cross-layer fusion, opt-in, regresses here) | 137 | +1% | -35% |

**HARD FLOOR ≤200 ms hit on every run.** SOFT TARGET ≤100 ms still 35-37ms away. The remaining gap is dominated by the LM head MatMul (2.1B MACs forward × 2 backward GEMMs) which is kernel-optimal at MKL for these shapes on this CPU.

Path to ≤100ms is genuinely hardware-dependent:
- **With AVX-512-BF16 hardware** (Cooper Lake / Sapphire Rapids / Zen 4 Genoa+): Phase G.5 BF16 would engage automatically via the smoke-perf gate, delivering an estimated 30-50ms reduction. Plus G.6 cross-layer fusion may flip from regression to benefit at larger workloads.
- **Without AVX-512-BF16** (this AMD Zen 2 dev box, pre-Cooper-Lake Intel): the 135ms floor is the achievable wall-time without algorithmic changes specific to the loss function.
