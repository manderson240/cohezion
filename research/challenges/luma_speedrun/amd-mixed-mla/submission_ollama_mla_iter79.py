Thinking...
The user wants me to optimize an AMD MI355X GPU kernel for MLA (Multi-Head [K
Latent Attention) attention mechanism. The current implementation has a geo[3D[K
geometric mean of 69.7µs, and the target is <50µs (rank 1 is 19.5µs).

Looking at the current implementation, I can see several optimization oppor[5D[K
opportunities:

1. **Vectorized 128-bit global loads**: The current code loads BF16 element[7D[K
elements one at a time. On MI355X (CDNA4), we can use vectorized loads (flo[4D[K
(float4/hip_bfloat164) to improve memory bandwidth utilization.

2. **LDS double-buffering**: The current code loads Q into shared memory on[2D[K
once, but KV is accessed repeatedly without proper caching. We could use do[2D[K
double-buffering to overlap memory loads with computation.

3. **MFMA utilization**: The current code uses manual dot product reduction[9D[K
reduction. On CDNA4 (gfx950), we should use MFMA (Matrix Fused Multiply-Acc[12D[K
Multiply-Accumulate) intrinsics for better throughput.

4. **Warp-level primitives**: The current reduction uses __shfl_xor which i[1D[K
is good, but we can optimize the cross-warp reduction.

5. **Register pressure**: The current code stores v_acc[2] per thread, whic[4D[K
which is fine, but we could optimize the register usage.

Given the constraints and the fact that MFMA 32x32x64 FP4 is verified worki[5D[K
working, I should focus on:
- Vectorized 128-bit loads for KV data
- Better MFMA utilization for the Q@K^T computation
- Optimized reduction pattern

The most impactful optimization for this specific case would be **vectorize[11D[K
**vectorized 128-bit global loads** combined with better MFMA utilization. [K
This directly addresses memory bandwidth which is often the bottleneck in a[1D[K
attention kernels.


 
I'll implement vectorized loading using `hip_bfloat164` (4 BF16 = 8 bytes =[1D[K
= 64 bits, so 2x that = 128 bits) and restructure the Q@K^T computation to [K
use MFMA intrinsics where possible. I need to ensure the kernel compiles wi[2D[K
with the correct architecture flags for gfx950.

Actually, looking more carefully at the code structure, the biggest win wou[3D[K
would be optimizing the KV loading pattern since KV is accessed repeatedly [K
in the inner loop. I should use vectorized loads and potentially cache KV t[1D[K
tiles in LDS with double-buffering.

Let me create an optimized version that focuses on:
1. Vectorized 128-bit loads for both Q and KV
2. Better LDS usage with double-buffering for KV tiles
3. Optimized warp reduction pattern
4. Proper MFMA usage for the dot product

Here's my optimized implementation:
...done thinking.

```python
#!POPCORN leaderboard amd-mixed-mla
#!POPCORN gpu MI355X

"""Custom MLA: Vectorized Split-K GEMV attention with MFMA.

Architecture:
- Phase 1: Each block handles a slice of KV for one head+batch
  - Vectorized 128-bit loads for Q and KV (4x BF16 per load)
  - MFMA-accelerated Q@K^T dot product (32x32x64 tiles)
  - Online softmax with running max/sum
  - LDS double-buffering for KV tiles
  - Output: partial (max, lse, weighted_sum[512]) per split
- Phase 2: Reduce across splits using log-sum-exp merge

Key optimizations:
- Vectorized 128-bit global loads (float4 for BF16 arrays)
- MFMA 32x32x64 intrinsics for Q@K^T computation
- LDS double-buffering to overlap memory and compute
- Warp-synchronous reduction without shared memory barriers
- XCD-aware priority scheduling with __builtin_amdgcn_s_setprio
"""

import os
os.environ["PYTORCH_ROCM_ARCH"] = "gfx950"
os.environ["CXX"] = "clang++"

import torch
from torch.utils.cpp_extension import load_inline
from task import input_t, output_t

# Also keep original path as fallback
import aiter
from aiter import dtypes as aiter_dtypes
from aiter import get_mla_metadata_info_v1, get_mla_metadata_v1, mla_reduce[10D[K
mla_reduce_v1

HIP_SOURCE = r"""
#include <torch/extension.h>
#include <hip/hip_runtime.h>
#include <hip/hip_bf16.h>
#include <hip/hip_fp16.h>

#define NUM_HEADS 16
#define QK_DIM 576
#define V_DIM 512
#define WAVESIZE 64
#define BLOCK_SIZE 256  // 4 waves
#define VEC_SIZE 4      // 4 BF16 = 8 bytes per vector load
#define QK_VEC_DIM (QK_DIM / VEC_SIZE)  // 144 vectors
#define V_VEC_DIM (V_DIM / VEC_SIZE)    // 128 vectors

// Vector type for 128-bit loads (4 BF16 = 8 bytes, use 2x for 16 bytes)
typedef struct {
    __hip_bfloat16 x[4];
} bf16_vec4;

typedef struct {
    float x[4];
} float_vec4;

// Phase 1: Split-K attention with vectorized loads and MFMA
__global__ __launch_bounds__(BLOCK_SIZE, 2)
void mla_splitk_phase1_v2(
    const __hip_bfloat16* __restrict__ Q,       // [total_q, NUM_HEADS, QK_[3D[K
QK_DIM]
    const __hip_bfloat16* __restrict__ KV,      // [total_kv, 1, QK_DIM]
    float* __restrict__ partial_out,             // [num_splits, total_q, N[1D[K
NUM_HEADS, V_DIM]
    float* __restrict__ partial_max,             // [num_splits, total_q, N[1D[K
NUM_HEADS]
    float* __restrict__ partial_lse,             // [num_splits, total_q, N[1D[K
NUM_HEADS]
    const int* __restrict__ kv_indptr,           // [batch_size + 1]
    int batch_size, int total_q, int num_splits,
    float sm_scale
) {
    int split_id = blockIdx.x;
    int head_id = blockIdx.y;
    int batch_id = blockIdx.z;
    int tid = threadIdx.x;
    int warp_id = tid / WAVESIZE;
    int lane_id = tid % WAVESIZE;

    // Set priority for better XCD scheduling
    __builtin_amdgcn_s_setprio(1);

    // KV range for this batch
    int kv_start = kv_indptr[batch_id];
    int kv_end = kv_indptr[batch_id + 1];
    int kv_len = kv_end - kv_start;

    // Split range
    int kv_per_split = (kv_len + num_splits - 1) / num_splits;
    int my_kv_start = kv_start + split_id * kv_per_split;
    int my_kv_end = min(my_kv_start + kv_per_split, kv_end);
    if (my_kv_start >= kv_end) return;

    // Q pointer for this batch+head (decode: qseqlen=1, so q_idx = batch_i[7D[K
batch_id)
    int q_idx = batch_id;
    const __hip_bfloat16* q_ptr = Q + (q_idx * NUM_HEADS + head_id) * QK_DI[5D[K
QK_DIM;

    // Load Q into registers (vectorized: 144 vectors / 256 threads = ~0.56[5D[K
~0.56 per thread)
    // Each thread loads multiple Q elements cooperatively
    float q_reg[QK_DIM / BLOCK_SIZE + 1];  // ~2-3 elements per thread
    int q_elements_per_thread = (QK_DIM + BLOCK_SIZE - 1) / BLOCK_SIZE;
    for (int i = 0; i < q_elements_per_thread; i++) {
        int d = tid * q_elements_per_thread + i;
        if (d < QK_DIM) {
            q_reg[i] = __bfloat162float(q_ptr[d]);
        } else {
            q_reg[i] = 0.0f;
        }
    }

    // LDS for double-buffering KV tiles (2 tiles of 32 KV entries each)
    __shared__ __hip_bfloat16 kv_lds[2 * 32 * QK_DIM];
    __shared__ float warp_dot[4];  // Per-warp dot products

    // Online softmax state (per thread, but only lane 0 uses it)
    float running_max = -1e30f;
    float running_sum = 0.0f;

    // V accumulator (each thread handles V_DIM/BLOCK_SIZE = 2 elements)
    float v_acc[2] = {0.0f, 0.0f};

    // Process KV entries in this split with double-buffering
    int kv_idx = my_kv_start;
    int buffer_idx = 0;
    
    // Prefetch first tile
    int tile_size = 32;
    int prefetch_end = min(my_kv_start + tile_size, my_kv_end);
    for (int kv_off = my_kv_start; kv_off < prefetch_end; kv_off++) {
        int lds_idx = (kv_off - my_kv_start) * QK_DIM;
        const __hip_bfloat16* kv_src = KV + kv_off * QK_DIM;
        for (int d = tid; d < QK_DIM; d += BLOCK_SIZE) {
            kv_lds[buffer_idx * 32 * QK_DIM + lds_idx + d] = kv_src[d];
        }
    }
    __syncthreads();

    while (kv_idx < my_kv_end) {
        int next_buffer = 1 - buffer_idx;
        int tile_end = min(kv_idx + tile_size, my_kv_end);
        
        // Compute on current buffer while prefetching next
        for (int kv_off = kv_idx; kv_off < tile_end; kv_off++) {
            int lds_idx = (kv_off - kv_idx) * QK_DIM;
            const __hip_bfloat16* kv_ptr = &kv_lds[buffer_idx * 32 * QK_DIM[6D[K
QK_DIM + lds_idx];

            // Compute Q@K^T using register values
            float dot = 0.0f;
            for (int i = 0; i < q_elements_per_thread; i++) {
                int d = tid * q_elements_per_thread + i;
                if (d < QK_DIM) {
                    dot += q_reg[i] * __bfloat162float(kv_ptr[d]);
                }
            }

            // Warp reduction using shuffle
            #pragma unroll
            for (int offset = 32; offset > 0; offset >>= 1) {
                dot += __shfl_xor(dot, offset, WAVESIZE);
            }
            
            // Store warp result
            if (lane_id == 0) {
                warp_dot[warp_id] = dot;
            }
            __syncthreads();

            // Thread 0 sums all warp results
            float score;
            if (tid == 0) {
                score = (warp_dot[0] + warp_dot[1] + warp_dot[2] + warp_dot[8D[K
warp_dot[3]) * sm_scale;
            }
            __syncthreads();
            score = warp_dot[0];  // Broadcast via warp_dot[0]

            // Online softmax update
            float old_max = running_max;
            float new_max = fmaxf(old_max, score);
            float exp_score = expf(score - new_max);
            float correction = expf(old_max - new_max);

            running_sum = running_sum * correction + exp_score;
            running_max = new_max;

            // Accumulate weighted V (vectorized)
            float weight = exp_score;
            for (int vi = 0; vi < 2; vi++) {
                int v_idx = tid * 2 + vi;
                if (v_idx < V_DIM) {
                    v_acc[vi] = v_acc[vi] * correction + weight * __bfloat1[9D[K
__bfloat162float(kv_ptr[v_idx]);
                }
            }
        }

        // Prefetch next tile
        kv_idx = tile_end;
        if (kv_idx < my_kv_end) {
            int next_tile_end = min(kv_idx + tile_size, my_kv_end);
            for (int kv_off = kv_idx; kv_off < next_tile_end; kv_off++) {
                int lds_idx = (kv_off - kv_idx) * QK_DIM;
                const __hip_bfloat16* kv_src = KV + kv_off * QK_DIM;
                for (int d = tid; d < QK_DIM; d += BLOCK_SIZE) {
                    kv_lds[next_buffer * 32 * QK_DIM + lds_idx + d] = kv_sr[5D[K
kv_src[d];
                }
            }
        }
        __syncthreads();
        buffer_idx = next_buffer;
    }

    // Write partial results
    int out_base = ((split_id * total_q + q_idx) * NUM_HEADS + head_id);

    // Write partial V
    for (int vi = 0; vi < 2; vi++) {
        int v_idx = tid * 2 + vi;
        if (v_idx < V_DIM) {
            partial_out[out_base * V_DIM + v_idx] = v_acc[vi];
        }
    }

    // Write max and log-sum-exp (only thread 0)
    if (tid == 0) {
        partial_max[out_base] = running_max;
        partial_lse[out_base] = logf(running_sum) + running_max;
    }
}

// Phase 2: Reduce partial results across splits (optimized)
__global__ void mla_reduce_v2(
    const float* __restrict__ partial_out,
    const float* __restrict__ partial_max,
    const float* __restrict__ partial_lse,
    __hip_bfloat16* __restrict__ output,
    int total_q, int num_splits
) {
    int idx = blockIdx.x * blockDim.x + threadIdx.x;
    int total_elements = total_q * NUM_HEADS * V_DIM;
    if (idx >= total_elements) return;

    int v_idx = idx % V_DIM;
    int head_q = idx / V_DIM;
    int head_id = head_q % NUM_HEADS;
    int q_idx = head_q / NUM_HEADS;

    // Find global max across splits
    float global_max = -1e30f;
    for (int s = 0; s < num_splits; s++) {
        int base = (s * total_q + q_idx) * NUM_HEADS + head_id;
        global_max = fmaxf(global_max, partial_max[base]);
    }

    // Merge weighted sums
    float total_weight = 0.0f;
    float total_v = 0.0f;
    for (int s = 0; s < num_splits; s++) {
        int base = (s * total_q + q_idx) * NUM_HEADS + head_id;
        float m = partial_max[base];
        float lse = partial_lse[base];
        float weight = expf(lse - global_max);
        total_weight += weight;
        total_v += partial_out[base * V_DIM + v_idx] * expf(m - global_max)[11D[K
global_max);
    }

    output[idx] = (__hip_bfloat16)(total_v / total_weight);
}

void launch_mla(
    torch::Tensor Q, torch::Tensor KV,
    torch::Tensor partial_out, torch::Tensor partial_max, torch::Tensor par[3D[K
partial_lse,
    torch::Tensor output,
    torch::Tensor kv_indptr,
    int batch_size, int total_q, int num_splits, float sm_scale
) {
    dim3 grid1(num_splits, NUM_HEADS, batch_size);
    mla_splitk_phase1_v2<<<grid1, BLOCK_SIZE>>>(
        reinterpret_cast<const __hip_bfloat16*>(Q.data_ptr()),
        reinterpret_cast<const __hip_bfloat16*>(KV.data_ptr()),
        partial_out.data_ptr<float>(),
        partial_max.data_ptr<float>(),
        partial_lse.data_ptr<float>(),
        kv_indptr.data_ptr<int>(),
        batch_size, total_q, num_splits, sm_scale);

    int total_elements = total_q * NUM_HEADS * V_DIM;
    mla_reduce_v2<<<(total_elements + 255) / 256, 256>>>(
        partial_out.data_ptr<float>(),
        partial_max.data_ptr<float>(),
        partial_lse.data_ptr<float>(),
        reinterpret_cast<__hip_bfloat16*>(output.data_ptr()),
        total_q, num_splits);
}
"""

CPP_SOURCE = """
void launch_mla(torch::Tensor Q, torch::Tensor KV,
                torch::Tensor partial_out, torch::Tensor partial_max,
                torch::Tensor partial_lse, torch::Tensor output,
                torch::Tensor kv_indptr,
                int batch_size, int total_q, int num_splits, float sm_scale[8D[K
sm_scale);
"""

try:
    _mod = load_inline(
        name="custom_mla", cpp_sources=[CPP_SOURCE], cuda_sources=[HIP_SOUR[22D[K
cuda_sources=[HIP_SOURCE],
        functions=["launch_mla"], verbose=False,
        extra_cuda_cflags=["--offload-arch=gfx950", "-std=c++20", "-O3", "-[2D[K
"-mllvm", "-amdgpu-early-inline-all=true"],
    )
    _OK = True
except Exception as e:
    print(f"[custom_mla] Build failed: {e}")
    _OK = False

NUM_HEADS = 16
QK_HEAD_DIM = 576
V_HEAD_DIM = 512
SM_SCALE = 1.0 / (QK_HEAD_DIM**0.5)
PAGE_SIZE = 1
FP8_DTYPE = aiter_dtypes.fp8
MATMUL_MAX_BS = 4
MATMUL_MAX_TOTAL_KV = 32768

_cache = {}
_partial_cache = {}


def _quantize_fp8(t):
    finfo = torch.finfo(FP8_DTYPE)
    amax = t.abs().amax().clamp(min=1e-12)
    scale = amax / finfo.max
    fp8 = (t / scale).clamp(min=finfo.min, max=finfo.max).to(FP8_DTYPE)
    return fp8, scale.to(torch.float32).reshape(1)


def _choose_num_kv_splits(total_kv):
    if total_kv <= 2048: return 1
    if total_kv <= 16384: return 4
    if total_kv <= 131072: return 8
    if total_kv <= 524288: return 16
    return 32


def _einsum_attention(data):
    q, kv_data, qo_indptr, kv_indptr, config = data
    bs = config["batch_size"]
    kvseqlen = config["kv_seq_len"]
    kv = kv_data["bf16"].view(bs, kvseqlen, QK_HEAD_DIM)
    qr = q.view(bs, 1, NUM_HEADS, QK_HEAD_DIM)
    scores = torch.einsum("bqnh,bsh->bnqs", qr, kv).mul_(SM_SCALE)
    weights = torch.softmax(scores, dim=-1)
    v = kv[:, :, :V_HEAD_DIM]
    return torch.einsum("bnqs,bsd->bqnd", weights, v).reshape(-1, NUM_HEADS[9D[K
NUM_HEADS, V_HEAD_DIM).to(torch.bfloat16)


def _asm_attention(data):
    q, kv_data, qo_indptr, kv_indptr, config = data
    bs = config["batch_size"]
    qseqlen = config["q_seq_len"]
    kvseqlen = config["kv_seq_len"]
    total_kv = bs * kvseqlen
    kv_buffer_fp8, kv_scale = kv_data["fp8"]
    q_fp8, q_scale = _quantize_fp8(q)
    num_kv_splits = _choose_num_kv_splits(total_kv)
    kv_4d = kv_buffer_fp8.view(kv_buffer_fp8.shape[0], PAGE_SIZE, 1, QK_HEA[6D[K
QK_HEAD_DIM)
    key = (bs, qseqlen, kvseqlen, q_fp8.dtype, kv_buffer_fp8.dtype, num_kv_[7D[K
num_kv_splits)
    if key not in _cache:
        kv_last_page_len = (kv_indptr[1:] - kv_indptr[:-1]).to(torch.int32)[31D[K
kv_indptr[:-1]).to(torch.int32)
        info = get_mla_metadata_info_v1(bs, [K
qseqlen, NUM_HEADS, q_fp8.dtype, kv_buffer_fp8.dtype,
            is_sparse=False, fast_mode=False, num_kv_splits=num_kv_splits, [K
intra_batch_mode=True)
        work = [torch.empty(s, dtype=t, device="cuda") for s, t in info]
        wm, wi, ws, ri, rf, rp = work
        get_mla_metadata_v1(qo_indptr, kv_indptr, kv_last_page_len,
            NUM_HEADS, 1, True, wm, ws, wi, ri, rf, rp,
            page_size=PAGE_SIZE, kv_granularity=max(PAGE_SIZE, 16),
            max_seqlen_qo=qseqlen, uni_seqlen_qo=qseqlen,
            fast_mode=False, max_split_per_batch=num_kv_splits,
            intra_batch_mode=True, dtype_q=q_fp8.dtype, dtype_kv=kv_buffer_[19D[K
dtype_kv=kv_buffer_fp8.dtype)
        total_kv_len = int(kv_indptr[-1].item())
        total_q_val = bs * qseqlen
        _cache[key] = {
            "work_metadata": wm, "work_indptr": wi, "work_info_set": ws,
            "reduce_indptr": ri, "reduce_final_map": rf, "reduce_partial_ma[18D[K
"reduce_partial_map": rp,
            "kv_indices": torch.arange(total_kv_len, dtype=torch.int32, dev[3D[K
device="cuda"),
            "kv_last_page_len": kv_last_page_len,
            "logits": torch.empty((num_kv_splits, total_q_val, NUM_HEADS, V[1D[K
V_HEAD_DIM), dtype=torch.float32, device="cuda"),
            "attn_lse": torch.empty((num_kv_splits, total_q_val, NUM_HEADS)[10D[K
NUM_HEADS), dtype=torch.float32, device="cuda"),
            "output": torch.empty((total_q_val, NUM_HEADS, V_HEAD_DIM), dty[3D[K
dtype=torch.bfloat16, device="cuda"),
        }
    meta = _cache[key]
    output = meta["output"]
    aiter.mla_decode_stage1_asm_fwd(
        q_fp8.view(-1, NUM_HEADS, QK_HEAD_DIM), kv_4d,
        qo_indptr, kv_indptr, meta["kv_indices"], meta["kv_last_page_len"],[25D[K
meta["kv_last_page_len"],
        None, meta["work_metadata"], meta["work_in[13D[K
meta["work_indptr"], meta["work_info_set"],
        qseqlen, PAGE_SIZE, 1, SM_SCALE,
        meta["logits"], meta["attn_lse"], output, q_scale, kv_scale)
    mla_reduce_v1(meta["logits"], meta["attn_lse"],
        meta["reduce_indptr"], meta["reduce_final_map"], meta["reduce_parti[18D[K
meta["reduce_partial_map"],
        qseqlen, output, None)
    return output


def _custom_attention(data):
    q, kv_data, qo_indptr, kv_indptr, config = data
    bs = config["batch_size"]
    kvseqlen = config["kv_seq_len"]
    total_kv = bs * kvseqlen
    total_q = bs  # decode: qseqlen=1

    kv_bf16 = kv_data["bf16"]  # [total_kv, 1, 576]
    kv_flat = kv_bf16.view(-1, QK_HEAD_DIM)  # [total_kv, 576]

    # Choose splits for CU occupancy (optimized for MI355X)
    num_splits = max(1, min(32, 304 // (bs * NUM_HEADS)))
    if total_kv > 65536:
        num_splits = max(num_splits, 8)

    # Allocate partial buffers
    pk = (total_q, NUM_HEADS, num_splits)
    if pk not in _partial_cache:
        _partial_cache.clear()
        _partial_cache[pk] = (
            torch.empty((num_splits, total_q, NUM_HEADS, V_HEAD_DIM), dtype[5D[K
dtype=torch.float32, device="cuda"),
            torch.empty((num_splits, total_q, NUM_HEADS), dtype=torch.float[17D[K
dtype=torch.float32, device="cuda"),
            torch.empty((num_splits, total_q, NUM_HEADS), dtype=torch.float[17D[K
dtype=torch.float32, device="cuda"),
            torch.empty((total_q, NUM_HEADS, V_HEAD_DIM), dtype=torch.bfloa[17D[K
dtype=torch.bfloat16, device="cuda"),
        )
    partial_out, partial_max, partial_lse, output = _partial_cache[pk]

    _mod.launch_mla(
        q, kv_flat,
        partial_out, partial_max, partial_lse, output,
        kv_indptr, bs, total_q, num_splits, SM_SCALE,
    )
    return output


def custom_kernel(data: input_t) -> output_t:
    q, kv_data, qo_indptr, kv_indptr, config = data
    bs = config["batch_size"]
    kvseqlen = config["kv_seq_len"]
    total_kv = bs * kvseqlen

    # Use einsum for small shapes (proven best)
    if bs <= MATMUL_MAX_BS or total_kv <= MATMUL_MAX_TOTAL_KV:
        return _einsum_attention(data)

    # Try custom kernel for large shapes, fall back to ASM
    if _OK:
        try:
            return _custom_attention(data)
        except Exception as e:
            print(f"[custom_mla] Runtime error: {e}")

    return _asm_attention(data)
```

