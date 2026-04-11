# LayerNorm: Complete Status Report

## File Map

| File | Role |
|---|---|
| `include/nn/NN.h` | User-facing `LayerNorm` class |
| `src/nn/LayerNorm.cpp` | Module forward, calls `autograd::layer_norm` |
| `include/autograd/operations/NormalizationOps.h` | Functional `layer_norm` declaration |
| `src/autograd/operations/NormalizationOps.cpp` | Forward dispatch + **CPU forward kernel** (lambda) + autograd graph wiring |
| `include/autograd/backward/NormalizationBackward.h` | `LayerNormBackward` node class |
| `src/autograd/backward/NormalizationBackward.cpp` | Backward dispatch + **CPU backward kernel** (lambda) |
| `include/ops/helpers/LayerNormKernels.h` | CUDA function declarations (3 forward, 3 backward overloads) |
| `src/Kernels/cuda/LayerNormKernels.cu` | All GPU kernels: forward + 2 backward kernels |

---

## PART 1 — LayerNorm Forward CPU

### Location
`src/autograd/operations/NormalizationOps.cpp` → `cpu_layer_norm_forward` lambda (L93–L124)

### What it does (code-proven)
```cpp
// L98-124: OpenMP parallel over rows
#pragma omp parallel for
for (int64_t i = 0; i < rows; ++i) {
    // Pass 1: compute mean (scalar loop)
    float sum = 0.0f;
    for (int64_t j = 0; j < cols; ++j) sum += static_cast<float>(row_x[j]);
    float mu = sum / cols;

    // Pass 2: compute variance (scalar loop)
    float sum_sq = 0.0f;
    for (int64_t j = 0; j < cols; ++j) {
        float diff = static_cast<float>(row_x[j]) - mu;
        sum_sq += diff * diff;
    }
    float var = sum_sq / cols;
    float rs = 1.0f / std::sqrt(var + eps);

    // Pass 3: normalize + gamma/beta (scalar loop)
    for (int64_t j = 0; j < cols; ++j) {
        float val = (static_cast<float>(row_x[j]) - mu) * rs;
        float g = gamma_ptr ? static_cast<float>(gamma_ptr[j]) : 1.0f;
        float b = beta_ptr  ? static_cast<float>(beta_ptr[j])  : 0.0f;
        row_y[j] = static_cast<T>(val * g + b);
    }
}
```

### Current Status
- **3 separate scalar loops** per row (read input 3 times)
- **No SIMD** (no AVX/SSE intrinsics)
- **No Welford** — uses two-pass mean then variance
- **OpenMP parallelism** over rows (outer loop only)
- **Accumulates in float** for all dtypes — correct behavior

### What PyTorch does (CPU)
`aten/src/ATen/native/cpu/layer_norm_kernel.cpp`:
- Uses `layer_norm_kernel_mixed_type<T, float>` — dispatched through PyTorch's vectorized `vec::Vectorized<T>` framework
- **SIMD vectorized**: uses AVX2 `__m256` / `__m256d` instructions under the hood via `at::vec`
- **Two-pass** still (mean then variance), but each pass is SIMD-vectorized
- Uses `AccumulateType<T>` (e.g., float for half dtype)

### What TensorFlow/XLA does (CPU)
- CPU path decomposes into XLA HLO ops (reduce + elementwise)
- XLA's CPU backend uses LLVM vectorization (auto-vectorized SIMD)
- For inference: can use oneDNN (MKL-DNN) via `onednn_layer_norm.h`

### Gaps / What can be done
| Gap | Impact | Fix |
|---|---|---|
| 3 passes over input (read 3x) | ~3x extra memory traffic | Use Welford to combine pass 1+2 → 2 passes like GPU |
| No SIMD on accumulation | 4-8x slower than SIMD | Add AVX2 `__m256` vectorized inner loop |
| OpenMP only over rows | Can't parallelize within a row (single long row) | Also parallelize inner reduce with reduction clause |
| Scalar gamma/beta application | Easy SIMD win | AVX2 vectorized multiply-add |

> [!NOTE]
> For training with GPU, the CPU path is almost never the bottleneck — data is on GPU. But for CPU-only inference or testing, this is significantly slower than PyTorch.

---

## PART 2 — LayerNorm Backward CPU

### Location
`src/autograd/backward/NormalizationBackward.cpp` → `cpu_layer_norm_backward` lambda (L44–L98)

### What it does (code-proven)
```cpp
// L54-71: PASS 1 — accumulate grad_gamma, grad_beta over all rows (NO OpenMP — race condition risk)
for (int64_t i = 0; i < rows; ++i) {
    for (int64_t j = 0; j < cols; ++j) {
        float val = (row_x[j] - mu) * rs;    // normalized x
        gw_acc[j] += gy * val;               // d_gamma
        gb_acc[j] += gy;                     // d_beta
    }
}

// L73-98: PASS 2 — compute grad_input per row (OpenMP outer)
#pragma omp parallel for
for (int64_t i = 0; i < rows; ++i) {
    // Inner pass A: compute sum1 = sum(dy*gamma), sum2 = sum(dy*gamma*x_norm)
    float sum1 = 0.0f, sum2 = 0.0f;
    for (int64_t j = 0; j < cols; ++j) { ... }

    // Inner pass B: compute grad_input using sum1, sum2
    for (int64_t j = 0; j < cols; ++j) {
        row_gx[j] = rs * (gy*g - (sum1 + val*sum2) / cols);
    }
}
```

### Current Status
- **gamma/beta grad**: serial loop (no OpenMP) + uses a `std::vector<float>` accumulator
- **input grad**: OpenMP over rows, but 2 scalar inner passes per row
- **No SIMD** anywhere
- **Total passes over input**: approximately 4 (2 for gamma/beta, 2 for input grad)

### What PyTorch does (CPU backward)
- Also two-kernel approach conceptually but vectorized
- Gamma/Beta grad uses parallel reduction with atomic accumulation or tiling to avoid races
- Input grad is vectorized using `at::vec`

### Gaps / What can be done
| Gap | Impact | Fix |
|---|---|---|
| Gamma/beta serial (no OMP) | Single-threaded on potentially huge rows × cols | Use atomic OMP reduction or tiled approach |
| No SIMD in any loop | 4-8x slower | AVX2 vectorize inner loops |
| 4 total data passes on input | Excessive memory reads | PyTorch fuses the two gamma/beta passes into one |

---

## PART 3 — LayerNorm Forward GPU

### Location
`src/Kernels/cuda/LayerNormKernels.cu` → `layer_norm_forward_kernel` (L59–L272)

### Kernel Signature
```cpp
template<typename T, typename AccT>
__global__ void layer_norm_forward_kernel(
    const T* x, const T* gamma, const T* beta,
    T* y, AccT* mean_out, AccT* rstd_out,
    int cols, AccT eps)
```

**Grid**: `<<<rows, 256>>>` — one block per row, 256 threads per block

### What it does (code-proven, 6 phases)

**Phase 1** (L80–L135): Vectorized local accumulation
- `float`: reinterprets row as `float4*` → loads 4 floats per instruction, accumulates `local_sum` and `local_sq_sum` 
- `__half`: reinterprets as `float4*` → gets 8 halfs per load, extracts via `__half2` → `__half22float2`, accumulates 8 elements per vector
- `__nv_bfloat16`: same pattern with `__nv_bfloat162` and `__bfloat1622float2`
- `#pragma unroll 4` on the loop

**Phase 2** (L137–L143): Convert local sums to Welford state in registers

**Phase 3** (L145–L153): Warp-level reduction via `__shfl_down_sync(0xffffffff, ...)` — 5 rounds of shuffle, zero memory ops

**Phase 4** (L155–L170): Block-level reduction via shared memory (`s_welford[32]`), only `lane_id == 0` writes, thread 0 merges all warps

**Phase 5** (L172–L179): Extract final `mu`, `rstd = rsqrtf(m2/cols + eps)`, thread 0 writes to global mean/rstd tensors

**Phase 6** (L181–L271): Vectorized normalize + write:
- `float`: `float4` reads of x, gamma, beta → compute 4 outputs → write `float4` to y
- `__half`: `float4` reads → extract `__half2` pairs → compute in float → pack back to `__half2` → write
- `__nv_bfloat16`: same pattern with bf16 intrinsics

### Current Status — **Well Optimized**
| Optimization | Status |
|---|---|
| Fused stats + normalize (1 kernel) | ✅ Done |
| Welford one-pass algorithm | ✅ Done |
| Vectorized loads float4 (float) | ✅ Done |
| Vectorized loads float4/half2x4 (fp16) | ✅ Done |
| Vectorized loads float4/bf16x4 (bf16) | ✅ Done |
| Warp shuffle reduction | ✅ Done |
| Shared memory block reduction | ✅ Done |
| AccT=float for stats (fp16/bf16 accumulate in f32) | ✅ Done |

### What PyTorch does differently (from actual source)

**PyTorch fast path** (`vectorized_layer_norm_kernel`, L248–L353):
- Uses `aligned_vector<T, vec_size>` (vec_size=4 hardcoded at L42)
- Custom `WelfordDataLN` struct with separate `mean`, `sigma2`, `count` fields (more cache-efficient layout than our 3-field struct)
- Uses `1.f/new_count` instead of proper division (L146): *"proper division is slow, this is less accurate but noticeably faster"*
- **Alignment check** before launch (L1106–1113): if pointers aren't 16-byte aligned or N%4 != 0, falls back to 2-kernel slow path
- 2D thread block: `dim3 threads(warp_size, num_threads()/warp_size)` — threads in X for warp, threads in Y for inter-warp

**PyTorch slow path** (when alignment fails):
- Kernel 1: `RowwiseMomentsCUDAKernel` - stats only
- Kernel 2: `LayerNormForwardCUDAKernel` - normalize only
- 2 kernel launches, 3 total reads of input

### Gaps vs PyTorch
| Gap | Impact | Fix |
|---|---|---|
| No alignment check | Could crash on unaligned data | Add `can_vectorize(ptr, alignment)` check like PyTorch L1106 |
| Block reduction is serial (thread 0 loops) | Minor latency for large blocks | Use tree reduction like PyTorch's `BlockReduce` |
| Fixed 256 threads regardless of N | Suboptimal for small N | Adaptive: `threads = min(256, nextPow2(cols))` like PyTorch |
| No fast reciprocal `1.f/n` in Welford merge | Minor: uses `/` instead | Use `1.f/n` with comment (PyTorch's approach) |

> [!IMPORTANT]
> The GPU forward kernel is **already well-optimized** and matches PyTorch's fast-path strategy. The gaps above are minor polishing items, not fundamental architectural deficiencies.

---

## PART 4 — LayerNorm Backward GPU

### Location
`src/Kernels/cuda/LayerNormKernels.cu` — **2 separate kernels** launched by `launch_layer_norm_backward` (L446–L478)

---

### Kernel A: `ln_backward_gamma_beta_kernel` — Why this exists

**Kernel Signature** (L321–L373):
```cpp
template<typename T>
__global__ void ln_backward_gamma_beta_kernel(
    const T* grad_y, const T* x,
    const float* mean, const float* rstd,
    float* grad_gamma, float* grad_beta,
    int rows, int cols)
```

**Grid**: `dim3 grid(blocks_x, blocks_y)`, `dim3 threads(32, 8)` — 2D block

**What it computes**:
```
grad_gamma[j] = sum over all rows of (grad_y[i,j] * norm_x[i,j])
grad_beta[j]  = sum over all rows of (grad_y[i,j])
```

This is a **column-wise reduction over ALL rows**. gamma and beta are per-column (shape `[cols]`), so we need to accumulate contributions from every single row of the batch into each column position.

**How it works** (L337–L372):
- `tx` (0-31) = column offset within a 32-wide tile
- `ty` (0-7) = row partition index within a tile
- Each block handles a 32-column tile
- Inner loop (`row += gridDim.y * 8`): each thread strides over its row subset
- Accumulates into `s_dgamma[8][32]` and `s_dbeta[8][32]` shared memory (2D shared mem = zero bank conflicts)
- `ty==0` does final reduction across the 8 y-threads and uses `atomicAdd` to global grad_gamma/grad_beta

**Why dedicated kernel**: Cannot merge into the input-grad kernel below, because that kernel is one-block-per-row and cannot do cross-row accumulation for gamma/beta.

---

### Kernel B: `ln_backward_input_kernel` — Why this exists

**Kernel Signature** (L376–L441):
```cpp
template<typename T>
__global__ void ln_backward_input_kernel(
    const T* grad_y, const T* x,
    const float* mean, const float* rstd, const T* gamma,
    T* grad_x, int cols)
```

**Grid**: `<<<rows, 256 or 512>>>` — one block per row (same as forward)

**What it computes** (the LayerNorm backward formula):
```
sum1 = sum_j(dy[j] * gamma[j])
sum2 = sum_j(dy[j] * gamma[j] * norm_x[j])
grad_x[j] = rstd * (dy[j]*gamma[j] - (sum1 + norm_x[j]*sum2) / cols)
```

**How it works** (L396–L440):
- **Pass A** (L399–L411): scalar loop, `#pragma unroll 4`, accumulates `sum_dy_gamma` and `sum_dy_gamma_norm` in registers
- Warp reduce via `warpReduceSum` (L410–L411)
- Block reduce via shared `s_sum1`, `s_sum2` + `atomicAdd` from each warp lane 0 (L413–L420)
- **Pass B** (L428–L440): scalar loop, `#pragma unroll 4`, computes final grad_x per element

**Why separate from gamma/beta kernel**: Needs per-row block reduction (sum1, sum2 are row-local scalars). Fundamentally different reduction structure from gamma/beta.

### Why BOTH backward kernels are needed

```
ln_backward_gamma_beta_kernel: reduces ACROSS rows → produces grad_gamma[cols], grad_beta[cols]
ln_backward_input_kernel:      reduces WITHIN a row → produces grad_x[rows, cols]
```
These are structurally incompatible — they cannot be fused into one kernel because one needs a column reduction (all rows) and the other needs a row reduction (all columns within one row).

### Current Status
| Optimization | Status |
|---|---|
| 2 kernels (correct, necessary) | ✅ |
| 2D thread block for gamma/beta (32×8) | ✅ Done — matches PyTorch's approach |
| atomicAdd for gamma/beta global accumulation | ✅ |
| Warp shuffle in input-grad kernel | ✅ |
| cudaMemset before gamma/beta kernel | ✅ |

### What PyTorch does differently (backward)

**Input grad** — PyTorch has TWO paths:
1. `layer_norm_grad_input_kernel` (L443): scalar loop with `unroll=4`
2. `layer_norm_grad_input_kernel_vectorized` (L464): uses `aligned_vector<T, vec_size>` for vectorized loads in both passes

**Our backward input kernel uses scalar loads** — no vectorization in Pass A or Pass B. PyTorch's vectorized backward is ~10-20% faster per their comment at L458: *"about 10% faster measured at PT operator level, with cases seeing a 2X speedup"*.

**Gamma/beta backward** — PyTorch uses `GammaBetaBackwardCUDAKernelTemplate` (L765) with:
- `block_dim_x × block_dim_y` thread block (fully template-parameterized for compile-time optimization)
- `rows_per_block_y` tiling factor (compile-time)
- `partial_reduction` flag: for M>>N case, skips final reduction and does it in a separate pass
- `aligned_grid` flag: skips boundary checks when grid aligns with tile size
- Warp-level `WARP_SHFL` to broadcast mean/rstd to all threads in warp (L699)

**Our gamma/beta kernel** is simpler: fixed `32×8` blocks, `atomicAdd` to global memory per block, no aligned_grid optimization, no partial reduction path.

### Gaps vs PyTorch (Backward)
| Gap | Impact | Fix |
|---|---|---|
| Input grad: no vectorized loads | 10-20% slower (PyTorch proven) | Add `float4` vectorized pass A + pass B like `layer_norm_grad_input_kernel_vectorized` |
| Gamma/beta: `atomicAdd` to global | Contention when blocks_x is large | Use intermediate buffer for partial sums, reduce in second pass (PyTorch's `partial_reduction`) |
| Gamma/beta: no `aligned_grid` fast path | Extra boundary check instructions per thread | Template `aligned_grid` bool to skip checks |
| Thread count for input grad: hardcoded 256/512 | Suboptimal for very small or very large cols | Match PyTorch's `kCUDABlockReduceNumThreads=512` |

---

## RMSNorm Status in Our Library

**Current status: NOT IMPLEMENTED.** No RMSNorm kernel, class, or autograd op exists in the library.

### How PyTorch implements RMSNorm — exact code proof

PyTorch uses the **same kernel** for both LayerNorm and RMSNorm via a `bool rms_norm` template parameter. From the actual source:

```cpp
// layer_norm_kernel.cu L58: stats kernel
template <typename T, typename T_ACC, bool rms_norm>
__global__ void RowwiseMomentsCUDAKernel(...) {
    ...
    if (threadIdx.x == 0) {
        if constexpr (!rms_norm){
            mean[i] = m1;                                         // L91: LayerNorm: write mean
            rstd[i] = rsqrt(m2 + eps);                           // L92
        } else {
            rstd[i] = rsqrt(m2 + m1*m1 + eps);                   // L94: RMSNorm: no mean subtraction
        }
    }
}

// layer_norm_kernel.cu L134: local Welford online sum
template<typename U, bool rms_norm> __device__
WelfordDataLN cuWelfordOnlineSum(const U val, const WelfordDataLN& curr_sum) {
    if constexpr (!rms_norm){
        // L140-148: standard Welford (mean + variance)
        U delta = val - curr_sum.mean;
        ...
    } else {
        // L149-151: RMSNorm: just accumulate sum of squares, no mean tracking
        return {0.f, curr_sum.sigma2 + val * val, 0};
    }
}

// Normalize step (L286-314): 
if constexpr (!rms_norm){
    out.val[ii] = gamma * (rstd * (x - mean)) + beta;  // LayerNorm
} else {
    out.val[ii] = gamma * (rstd * x);                  // RMSNorm: no mean subtraction, no beta
}
```

**The `bool rms_norm` is a compile-time `constexpr` template parameter** — all `if constexpr (!rms_norm)` branches are evaluated at compile time. The compiler generates **two completely separate PTX instructions** for the two instantiations (`rms_norm=false` = LayerNorm, `rms_norm=true` = RMSNorm). There is absolutely **zero runtime overhead** from the bool. The branching cost is compile-time only.

### Is PyTorch's approach (fused with bool) better or should we have separate kernels?

**PyTorch's fused bool template approach is better.** Reasons:
1. **Zero overhead**: `if constexpr` is resolved at compile-time → separate PTX per instantiation
2. **Code maintenance**: One kernel = one place to fix bugs, add optimizations
3. **All optimizations apply to both**: any improvement to vectorization or Welford applies to both LN and RMSNorm automatically
4. **Proven**: NVIDIA uses this pattern. TensorFlow/XLA also uses a single reduction-normalize pattern for both via HLO
5. The only downside is longer compile time (2× kernel instantiations) — not a runtime concern

**Recommendation**: Implement RMSNorm by adding `bool rms_norm` template parameter to our existing `layer_norm_forward_kernel`. Changes needed:
- Phase 1 stats: when `rms_norm=true`, compute only sum-of-squares (no mean), set `local_sum=0`
- Phase 5: when `rms_norm=true`, `rstd = rsqrtf(m2/cols + eps)` same formula, but `mu=0`
- Phase 6: when `rms_norm=true`, skip `- mu` in normalize, skip `+ bv` (no beta in RMSNorm)
- Add `rms_norm_forward_cuda` overloads in header that call the same kernel with `rms_norm=true`
- No new file needed

---

## Are Only Forward Ops Wrapped in Autograd? Or Backward Too?

**Only the forward function is wrapped in the autograd graph.**

From `NormalizationOps.cpp` L142–L162:
```cpp
// This is in the FORWARD function (layer_norm)
if (GradMode::is_enabled() && (input.requires_grad() || weight.requires_grad() || ...)) {
    auto grad_fn = std::make_shared<LayerNormBackward>(input, mean, rstd, weight, ...);
    grad_fn->set_next_edge(0, get_grad_edge(input));       // edge to input's grad
    grad_fn->set_next_edge(1, get_grad_edge(weight));      // edge to gamma's grad
    grad_fn->set_next_edge(2, get_grad_edge(bias));        // edge to beta's grad
    output.set_grad_fn(grad_fn);                           // attach to output
}
```

The `LayerNormBackward::apply()` in `NormalizationBackward.cpp` is called **by the autograd engine** when `.backward()` is called on the loss. It is NOT wrapped in another autograd op — it just executes the gradient math directly. This is correct. Backward functions don't get wrapped again (that would cause infinite recursion).

---

## Summary Table (Pre-Optimization)

| Part | Current State | Missing vs PyTorch |
|---|---|---|
| **CPU Forward** | 3 scalar passes, OMP over rows | No SIMD, Welford would save 1 pass |
| **CPU Backward** | 4 scalar passes, gamma/beta serial | No SIMD, gamma/beta needs OMP reduce |
| **GPU Forward** | Fused, Welford, float4, shfl — solid | Alignment check, adaptive thread count |
| **GPU Backward** | 2 kernels (correct), warp shfl | Input grad: no vectorized loads; gamma/beta: no partial reduce |
| **RMSNorm** | Not implemented | Add `bool rms_norm` template param to existing kernel |

---

## PART 6 — Restructuring & Optimization (Completed)

### Architecture Change: Separated Math Engine from Autograd

Previously, CPU forward/backward kernels were **embedded as lambdas** inside `NormalizationOps.cpp` (autograd wrapper) and `NormalizationBackward.cpp`. This mixed computation with autograd graph wiring — unlike how PyTorch separates them and how our own GELU/Activation ops are structured.

**New Architecture** (matches GELU pattern exactly):

```
nn::LayerNorm::forward(input)
    └── autograd::layer_norm(...)  [NormalizationOps.cpp — thin wrapper, graph only]
        └── layer_norm_forward(...)  [Normalizations.cpp — pure math, CPU/GPU dispatch]
            ├── CPU: cpu_layer_norm_forward_impl<T>() [AVX2 + Welford]
            └── GPU: cuda::layer_norm_forward_cuda()  [LayerNormKernels.cu]

nn::RMSNorm::forward(input)
    └── autograd::rms_norm(...)  [NormalizationOps.cpp — thin wrapper]
        └── rms_norm_forward(...)  [Normalizations.cpp — pure math]
            ├── CPU: cpu_rms_norm_forward_impl<T>() [AVX2 + one-pass]
            └── GPU: cuda::rms_norm_forward_cuda()  [same .cu file, rms_norm=true]
```

### New File Map

| File | Role |
|---|---|
| `include/ops/UnaryOps/Normalizations.h` | **NEW** — Pure math API: `layer_norm_forward/backward`, `rms_norm_forward/backward` |
| `src/UnaryOps/cpu/Normalizations.cpp` | **NEW** — Optimized CPU kernels + CPU/GPU dispatch for all norm ops |
| `src/autograd/operations/NormalizationOps.cpp` | **REFACTORED** — Thin autograd wrapper only (graph wiring) |
| `src/autograd/backward/NormalizationBackward.cpp` | **REFACTORED** — Thin backward, delegates to `layer_norm_backward()` |
| `include/autograd/backward/NormalizationBackward.h` | **UPDATED** — Added `RMSNormBackward` node class |
| `include/autograd/operations/NormalizationOps.h` | **UPDATED** — Added `rms_norm()` declaration |
| `include/ops/helpers/LayerNormKernels.h` | **UPDATED** — Added RMSNorm CUDA declarations (3 fwd + 3 bwd overloads) |
| `src/Kernels/cuda/LayerNormKernels.cu` | **UPDATED** — Fused `bool rms_norm` template, vectorized backward |
| `include/nn/NN.h` | **UPDATED** — Added `RMSNorm` class |
| `src/nn/LayerNorm.cpp` | **UPDATED** — Added `RMSNorm` constructor + forward |
| `include/TensorLib.h` | **UPDATED** — Added `#include "ops/UnaryOps/Normalizations.h"` |

---

### CPU Forward Optimizations Applied

| Optimization | Before | After |
|---|---|---|
| **Data passes** | 3 (mean, variance, normalize) | 2 (Welford one-pass stats, normalize) |
| **Inner loop SIMD** | Scalar only | AVX2 `Vectorized<float>` (8-wide) |
| **Welford algorithm** | Not used (two-pass mean then variance) | Welford online — single pass for mean+variance |
| **Float32 specialization** | Same as fp16/bf16 path | Direct `Vec::loadu`/`storeu` — no upcast overhead |
| **Normalize pass** | Scalar mul/add | `Vec::fmadd` (fused multiply-add) |
| **fp16/bf16 support** | Upcast in scalar loop | Upcast to float SIMD, compute, downcast back |

### CPU Backward Optimizations Applied

| Optimization | Before | After |
|---|---|---|
| **gamma/beta grad parallelism** | Serial (no OpenMP — race condition risk) | OMP parallel with per-thread private buffers + vectorized reduction |
| **gamma/beta SIMD** | Scalar accumulation | AVX2 vectorized accumulate + reduce |
| **Input grad SIMD** | Scalar inner loops | AVX2 vectorized sum1/sum2 accumulation + grad computation |
| **Float32 specialization** | Same as generic | Direct `Vec::loadu`/`storeu` — zero upcast cost |
| **Total data passes** | ~4 (2 for gamma/beta, 2 for input grad) | Same count but each pass is ~4-8x faster with SIMD |

### GPU Forward: Fused RMSNorm via `bool rms_norm` Template

PyTorch's approach: single kernel with `bool rms_norm` compile-time template parameter. We now do the same.

```cpp
template<typename T, typename AccT, bool rms_norm>
__global__ void norm_forward_kernel(...)
```

- `rms_norm=false` → standard LayerNorm (Welford mean+var, normalize with beta)
- `rms_norm=true` → RMSNorm (sum-of-squares only, no mean subtraction, no beta)
- All `if constexpr` branches → separate PTX at compile time, **zero runtime overhead**
- Both share identical vectorized load/store paths (float4, half2x4, bf16x4)

### GPU Backward: Vectorized Input Grad Kernel

| Change | Before | After |
|---|---|---|
| **Pass A (accumulate)** | Scalar loop with `#pragma unroll 4` | `float4` vectorized loads for fp32 (4 elements per instruction) |
| **Pass B (grad_x)** | Scalar loop with `#pragma unroll 4` | `float4` vectorized load/store for fp32 |
| **Expected speedup** | Baseline | ~10-20% faster (PyTorch's measured improvement for vectorized backward) |

### RMSNorm: Full Implementation

| Component | Status |
|---|---|
| `nn::RMSNorm` class (weight only, no bias) | ✅ |
| `autograd::rms_norm()` with autograd graph | ✅ |
| CPU forward: one-pass sum-of-squares + AVX2 normalize | ✅ |
| CPU backward: OMP parallel gamma grad + per-row input grad | ✅ |
| GPU forward: fused kernel (`rms_norm=true`), all 3 dtypes | ✅ |
| GPU backward: gamma kernel + input kernel, all 3 dtypes | ✅ |
| fp32, fp16, bf16 dispatch paths | ✅ |

### Updated Summary Table (Post-Optimization)

| Part | State | vs PyTorch |
|---|---|---|
| **CPU Forward** | Welford one-pass + AVX2 SIMD, 2 passes | Matches PyTorch's vectorized two-pass approach |
| **CPU Backward** | AVX2 SIMD + OMP parallel reduction | Matches PyTorch's parallel vectorized backward |
| **GPU Forward** | Fused Welford + float4 + rms_norm bool template | Matches PyTorch's fused fast-path strategy |
| **GPU Backward** | float4 vectorized input kernel + 2D gamma/beta kernel | Matches PyTorch's vectorized backward path |
| **RMSNorm** | Full implementation (CPU + GPU, fwd + bwd, 3 dtypes) | Same `bool rms_norm` template approach as PyTorch |
| **Architecture** | Separated math engine from autograd (like GELU pattern) | Clean 3-layer separation matching PyTorch |

### Remaining Minor Gaps (Low Priority)

| Gap | Impact | Notes |
|---|---|---|
| No pointer alignment check on GPU | Could theoretically crash on unaligned data | Add `can_vectorize()` check like PyTorch L1106 |
| Fixed 256 threads on GPU | Suboptimal for very small cols | Add `threads = min(256, nextPow2(cols))` |
| Block reduction serial (thread 0 loops warps) | Minor latency | Use tree reduction for large block counts |
| No `aligned_grid` fast path in gamma/beta backward | Extra boundary check instructions | Template `aligned_grid` bool |

---

## PART 7 — Benchmark Results

### Test Configuration

| Setting | Value |
|---|---|
| **Hardware** | NVIDIA GeForce RTX 3060 (sm_86), 20 CPU threads |
| **Compiler** | g++ (C++20, -O3, -mavx2, -mfma), nvcc (CUDA 13.0, --use_fast_math, sm_86) |
| **Dtype** | Float32 for all benchmarks |
| **Warmup** | 5 iterations (discarded) |
| **Timed iterations** | 50 (scaling test), 100 (framework comparison) |
| **CUDA sync** | `cudaDeviceSynchronize()` before start and after end of timed section |
| **Seeds** | 1337 (input tensors), 42 (bias/gamma), 99 (grad tensors) — deterministic |
| **Training size** | [8, 1024, 384] = 3.1M elements (from `gpt2_attn_fixed.cpp`: batch=8, seq=1024, n_embd=384) |

### Test Files

| File | Purpose | What it measures |
|---|---|---|
| `layernorm_scaling_test.cpp` | NEW code, 7 tensor sizes | `layer_norm_forward/backward` + `rms_norm_forward/backward` (pure math, no autograd overhead) |
| `layernorm_before_opt_test.cpp` | OLD code baseline (for colleague's unmodified repo) | `autograd::layer_norm()` forward + full `.backward()` (includes autograd graph creation) |
| `bench_pytorch_layernorm.py` | PyTorch 2.7.1+cu126 comparison | `F.layer_norm`, `F.rms_norm`, forward + backward, same shape/seed |
| `bench_tensorflow_layernorm.py` | TensorFlow 2.19.0 comparison | `keras.layers.LayerNormalization`, manual RMSNorm, same shape/seed |

### Tensor Sizes Tested (Scaling)

| Label | Shape | Elements | Notes |
|---|---|---|---|
| Tiny | [1, 128, 128] | 16K | Small model test |
| Small | [1, 512, 512] | 262K | |
| Medium | [8, 1024, 384] | 3.1M | **GPT-2 training size** |
| GPT2 | [8, 1024, 768] | 6.3M | Standard GPT-2 hidden |
| Large | [32, 1024, 768] | 25.2M | Larger batch |
| XLarge | [64, 1024, 768] | 50.3M | |
| Huge | [64, 2048, 1024] | 134.2M | Stress test |

---

### Before vs After — Training Size [8, 1024, 384]

Tested on same machine (RTX 3060). OLD = colleague's unmodified repo with `autograd::layer_norm()`. NEW = optimized `layer_norm_forward/backward()`.

| Operation | **OLD** | **NEW** | **Speedup** |
|---|---|---|---|
| **CPU Forward** | 1.728ms | 0.141ms | **12.3x faster** |
| **CPU Backward** | 25.940ms | 4.637ms | **5.6x faster** |
| **GPU Forward** | 0.113ms | 0.106ms | ~1.0x (same kernel) |
| **GPU Backward** (autograd path) | 0.866ms | 0.799ms | ~1.1x |
| **GPU Backward** (kernel only) | N/A | 0.292ms | — |

**Why GPU forward is unchanged**: The GPU forward kernel (`norm_forward_kernel<float, float, false>`) generates identical PTX to the old `layer_norm_forward_kernel<float, float>`. Only the template was extended with `bool rms_norm`, which compiles away for `false`.

**Why GPU backward autograd path shows modest improvement**: The 0.866→0.799ms measurement includes autograd overhead (~0.5ms: graph creation, tensor allocation, engine dispatch). The actual kernel speedup from float4 vectorization is visible in kernel-only measurement (0.292ms).

**Why CPU wins are massive**: Old CPU code had zero SIMD (pure scalar loops) and serial gamma/beta accumulation. New code has AVX2 8-wide SIMD + Welford one-pass + OMP parallel reduction.

---

### Full Scaling Results — NEW Code (LayerNorm)

**Forward (pure math, no autograd):**

| Size | CPU (ms) | GPU (ms) | GPU Speedup |
|---|---|---|---|
| Tiny [1,128,128] = 16K | 0.046 | 0.003 | 15.3x |
| Small [1,512,512] = 262K | 0.025 | 0.008 | 3.1x |
| Medium [8,1024,384] = 3.1M | 0.133 | 0.108 | 1.2x |
| GPT2 [8,1024,768] = 6.3M | 0.283 | 0.158 | 1.8x |
| Large [32,1024,768] = 25.2M | 7.270 | 0.624 | 11.7x |
| XLarge [64,1024,768] = 50.3M | 13.304 | 1.264 | 10.5x |
| Huge [64,2048,1024] = 134.2M | 32.128 | 3.620 | 8.9x |

**Backward (pure math, no autograd):**

| Size | CPU (ms) | GPU (ms) | GPU Speedup |
|---|---|---|---|
| Tiny [1,128,128] = 16K | 0.119 | 0.017 | 7.0x |
| Small [1,512,512] = 262K | 0.557 | 0.030 | 18.6x |
| Medium [8,1024,384] = 3.1M | 4.853 | 0.305 | 15.9x |
| GPT2 [8,1024,768] = 6.3M | 10.554 | 0.466 | 22.6x |
| Large [32,1024,768] = 25.2M | 61.671 | 1.891 | 32.6x |
| XLarge [64,1024,768] = 50.3M | 121.892 | 3.803 | 32.1x |
| Huge [64,2048,1024] = 134.2M | 319.742 | 9.962 | 32.1x |

---

### Full Scaling Results — NEW Code (RMSNorm)

**Forward:**

| Size | CPU (ms) | GPU (ms) | GPU Speedup |
|---|---|---|---|
| Tiny [1,128,128] = 16K | 0.033 | 0.003 | 11.0x |
| Small [1,512,512] = 262K | 0.024 | 0.006 | 4.0x |
| Medium [8,1024,384] = 3.1M | 0.071 | 0.088 | 0.8x (CPU wins at this size) |
| GPT2 [8,1024,768] = 6.3M | 0.213 | 0.157 | 1.4x |
| Large [32,1024,768] = 25.2M | 8.393 | 0.653 | 12.9x |
| XLarge [64,1024,768] = 50.3M | 14.122 | 1.328 | 10.6x |
| Huge [64,2048,1024] = 134.2M | 31.567 | 3.591 | 8.8x |

**Backward:**

| Size | CPU (ms) | GPU (ms) | GPU Speedup |
|---|---|---|---|
| Tiny [1,128,128] = 16K | 0.110 | 0.007 | 15.7x |
| Small [1,512,512] = 262K | 0.565 | 0.029 | 19.5x |
| Medium [8,1024,384] = 3.1M | 4.804 | 0.296 | 16.2x |
| GPT2 [8,1024,768] = 6.3M | 10.531 | 0.496 | 21.2x |
| Large [32,1024,768] = 25.2M | 61.693 | 2.002 | 30.8x |
| XLarge [64,1024,768] = 50.3M | 122.264 | 3.960 | 30.9x |
| Huge [64,2048,1024] = 134.2M | 321.071 | 9.965 | 32.2x |

---

### Framework Comparison — [8, 1024, 384] (GPU, fp32)

| Operation | **Ours** | **PyTorch 2.7** | **TF 2.19** | Ours vs PT | Ours vs TF |
|---|---|---|---|---|---|
| LN Forward | 0.107ms | 0.103ms | 0.474ms | 0.96x | **4.4x faster** |
| LN Backward | 0.292ms | 0.339ms | 2.683ms | **1.16x faster** | **9.2x faster** |
| RMS Forward | 0.081ms | 0.299ms | 0.082ms | **3.7x faster** | ~1.0x |
| RMS Backward | 0.289ms | 1.165ms | 1.705ms | **4.0x faster** | **5.9x faster** |

| Operation | **Ours** | **PyTorch 2.7** | **TF 2.19** | Ours vs PT | Ours vs TF |
|---|---|---|---|---|---|
| LN Forward (CPU) | 0.142ms | 0.118ms | 2.522ms | 0.83x | **17.8x faster** |
| RMS Forward (CPU) | 0.070ms | 0.294ms | 0.557ms | **4.2x faster** | **8.0x faster** |

> **Note:** PyTorch backward timings include forward pass (Python `.backward()` requires forward first). Our backward-only measurement is kernel-only. TF backward also includes forward.
