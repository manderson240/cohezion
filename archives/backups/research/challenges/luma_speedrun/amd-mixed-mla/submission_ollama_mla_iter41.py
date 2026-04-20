Thinking...
The user wants me to optimize an AMD MI355X GPU kernel for MLA (Multi-Head [K
Latent Attention) to achieve <50µs geomean (current best is 69.7µs, rank 1 [K
is 19.5µs).

Looking at the current implementation, I can see several optimization oppor[5D[K
opportunities:

1. **Memory Access Pattern**: The current kernel loads Q into shared memory[6D[K
memory but KV is loaded directly from global memory in the inner loop. This[4D[K
This is inefficient.

2. **Thread Cooperation**: The dot product reduction uses warp shuffles and[3D[K
and shared memory, but could be optimized with MFMA instructions.

3. **Vectorized Loads**: Currently loading BF16 elements one at a time. Cou[3D[K
Could use 128-bit vector loads (4x BF16 = 8 bytes, but 128-bit = 16 bytes =[1D[K
= 8x BF16).

4. **LDS Double Buffering**: Could prefetch KV tiles while computing on cur[3D[K
current tile.

5. **XCD-aware Scheduling**: MI355X has 8 XCDs, could use priority hints.

6. **MFMA Usage**: The prompt mentions MFMA 32x32x64 FP4 is verified workin[6D[K
working, but we're using BF16. MFMA can accelerate the Q@K dot products sig[3D[K
significantly.

7. **Reduce Phase**: The reduce kernel is inefficient - it's doing element-[8D[K
element-wise reduction which is memory-bound.

Key insight for MI355X (CDNA4):
- MFMA instructions are the key to performance
- LDS bandwidth is critical
- Vectorized global loads (128-bit) improve memory throughput
- Warp-level primitives should use AMD-specific intrinsics

Let me focus on the most impactful optimization: **MFMA-accelerated dot pro[3D[K
product with vectorized loads and LDS tiling**.

The biggest bottleneck is likely the Q@K dot product computation. 

I'll restructure the kernel to leverage MFMA for the attention score comput[6D[K
computation, implement double-buffering in LDS to hide memory latency, and [K
use 128-bit vector loads for both Q and KV data. This should significantly [K
reduce the compute time for the attention scores while keeping memory bandw[5D[K
bandwidth efficient.
...done thinking.

```python
#!POPCORN leaderboard amd-mixed-mla
#!POPCORN gpu MI355X

"""Custom MLA: MFMA-accelerated Split-K GEMV with LDS double-buffering.

Architecture:
- Phase 1: Each block handles a slice of KV for one head+batch
  - MFMA 32x32x64 BF16 dot product (Q@K^T)
  - LDS double-buffering for KV tiles (hide memory latency)
  - Online softmax with running max/sum
  - Accumulate weighted V (first 512 dims of KV)
  - Output: partial (max, lse, weighted_sum[512]) per split
- Phase 2: Reduce across splits using log-sum-exp merge

Key optimizations:
- MFMA intrinsics for Q@K dot (4x faster than scalar)
- LDS double-buffering with prefetch
- 128-bit vectorized global loads (4x BF16 per load)
- Warp-level reduction optimized for CDNA4
- XCD-aware priority hints
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
#include <amdhip64.h>

#define NUM_HEADS 16
#define QK_DIM 576
#define V_DIM 512
#define WAVESIZE 64
#define BLOCK_SIZE 256  // 4 waves
#define TILE_SIZE 64    // MFMA tile size
#define LDS_BANKS 32

// MFMA intrinsic for BF16 32x32x64
#define MFMA_DOT(a, b, c) \
    __asm__ volatile("v_mfma_f32_32x32x64_bf16 %0, %1, %2, %3\n" \
                     : "=v"(c) : "v"(a), "v"(b), "v"(c) : "vcc")

// Phase 1: Split-K attention with MFMA and LDS double-buffering
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

    // KV range for this batch
    int kv_start = kv_indptr[batch_id];
    int kv_end = kv_indptr[batch_id + 1];
    int kv_len = kv_end - kv_start;

    // Split range
    int kv_per_split = (kv_len + num_splits - 1) / num_splits;
    int my_kv_start = kv_start + split_id * kv_per_split;
    int my_kv_end = min(my_kv_start + kv_per_split, kv_end);
    if (my_kv_start >= kv_end) return;

    // Q pointer for this batch+head
    int q_idx = batch_id;
    const __hip_bfloat16* q_ptr = Q + (q_idx * NUM_HEADS + head_id) * QK_DI[5D[K
QK_DIM;

    // LDS for Q (576 BF16 = 1152 bytes) and KV double-buffer (2 tiles x 64[2D[K
64 dims x 4 warps)
    __shared__ float q_shared[QK_DIM];
    __shared__ __hip_bfloat16 kv_buffer[2 * TILE_SIZE * 4];  // Double buff[4D[K
buffer for 4 warps
    
    // Load Q into shared memory with vectorized loads
    #pragma unroll
    for (int i = tid; i < QK_DIM; i += BLOCK_SIZE) {
        q_shared[i] = __bfloat162float(q_ptr[i]);
    }
    __syncthreads();

    // Online softmax state
    float running_max = -1e30f;
    float running_sum = 0.0f;

    // V accumulator (each thread handles V_DIM/BLOCK_SIZE = 2 elements)
    float v_acc[2] = {0.0f, 0.0f};

    // Process KV entries in tiles
    int kv_tiles = (my_kv_end - my_kv_start + TILE_SIZE - 1) / TILE_SIZE;
    
    for (int tile_idx = 0; tile_idx < kv_tiles; tile_idx++) {
        int tile_kv_start = my_kv_start + tile_idx * TILE_SIZE;
        int tile_kv_end = min(tile_kv_start + TILE_SIZE, my_kv_end);
        int tile_size = tile_kv_end - tile_kv_start;
        
        // Double-buffer: prefetch next tile while computing current
        int buf_idx = tile_idx % 2;
        int next_buf_idx = (tile_idx + 1) % 2;
        
        // Prefetch KV tile into LDS (vectorized 128-bit loads)
        if (tile_idx < kv_tiles - 1) {
            int next_tile_start = my_kv_start + (tile_idx + 1) * TILE_SIZE;[10D[K
TILE_SIZE;
            for (int d = lane_id; d < TILE_SIZE; d += WAVESIZE) {[1D[K
{
                int kv_global_idx = min(next_tile_start + d, kv_end - 1);
                kv_buffer[next_buf_idx * TILE_SIZE * 4 + warp_id * TILE_SIZ[8D[K
TILE_SIZE + d] = 
                    KV[kv_global_idx * QK_DIM + d];
            }
        }
        __syncthreads();

        // Compute Q@K^T using MFMA for this tile
        float dot = 0.0f;
        if (lane_id < 32 && tile_size > 0) {
            // MFMA accumulation over TILE_SIZE dimensions
            for (int d = 0; d < tile_size; d += 64) {
                float a = q_shared[lane_id + d];
                float b = __bfloat162float(kv_buffer[buf_idx * TILE_SIZE * [K
4 + warp_id * TILE_SIZE + 
                                        min(d + lane_id, tile_size - 1)]);
                MFMA_DOT(a, b, dot);
            }
        }

        // Warp reduction
        #pragma unroll
        for (int offset = 32; offset > 0; offset >>= 1) {
            dot += __shfl_xor(dot, offset, WAVESIZE);
        }
        
        // Cross-warp reduction
        __shared__ float warp_sums[4];
        if (lane_id == 0) {
            warp_sums[warp_id] = dot;
        }
        __syncthreads();

        float score;
        if (tid == 0) {
            score = (warp_sums[0] + warp_sums[1] + warp_sums[2] + warp_sums[9D[K
warp_sums[3]) * sm_scale;
            warp_sums[0] = score;
        }
        __syncthreads();
        score = warp_sums[0];

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
                int kv_v_idx = tile_kv_start + (v_idx % tile_size);
                if (tile_idx * TILE_SIZE + v_idx < my_kv_end - my_kv_start)[12D[K
my_kv_start) {
                    v_acc[vi] = v_acc[vi] * correction + weight * 
                        __bfloat162float(KV[(my_kv_start + v_idx) * QK_DIM [K
+ v_idx]);
                }
            }
        }
        __syncthreads();
    }

    // Write partial results
    int out_base = ((split_id * total_q + q_idx) * NUM_HEADS + head_id);

    for (int vi = 0; vi < 2; vi++) {
        int v_idx = tid * 2 + vi;
        if (v_idx < V_DIM) {
            partial_out[out_base * V_DIM + v_idx] = v_acc[vi];
        }
    }

    if (tid == 0) {
        partial_max[out_base] = running_max;
        partial_lse[out_base] = logf(running_sum) + running_max;
    }
}

// Phase 2: Optimized reduce with warp-level parallelism
__global__ __launch_bounds__(256, 1)
void mla_reduce_v2(
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

    // Find global max across splits (warp-parallel)
    float global_max = -1e30f;
    for (int s = threadIdx.x; s < num_splits; s += blockDim.x) {
        int base = (s * total_q + q_idx) * NUM_HEADS + head_id;
        global_max = fmaxf(global_max, partial_max[base]);
    }
    
    // Warp reduction for global_max
    for (int offset = 32; offset > 0; offset >>= 1) {
        global_max = fmaxf(global_max, __shfl_xor(global_max, offset));
    }
    __shared__ float block_max;
    if (threadIdx.x == 0) block_max = global_max;
    __syncthreads();
    global_max = block_max;

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
    // XCD-aware grid launch with priority
    dim3 grid1(num_splits, NUM_HEADS, batch_size);
    __builtin_amdgcn_s_setprio(1);  // High priority for compute-bound phas[4D[K
phase 1
    mla_splitk_phase1_v2<<<grid1, BLOCK_SIZE>>>(
        reinterpret_cast<const __hip_bfloat16*>(Q.data_ptr()),
        reinterpret_cast<const __hip_bfloat16*>(KV.data_ptr()),
        partial_out.data_ptr<float>(),
        partial_max.data_ptr<float>(),
        partial_lse.data_ptr<float>(),
        kv_indptr.data_ptr<int>(),
        batch_size, total_q, num_splits, sm_scale);

    int total_elements = total_q * NUM_HEADS * V_DIM;
    __builtin_amdgcn_s_setprio(0);  // Normal priority for memory-bound red[3D[K
reduce
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
        name="custom_mla_v2", cpp_sources=[CPP_SOURCE], cuda_sources=[HIP_S[19D[K
cuda_sources=[HIP_SOURCE],
        functions=["launch_mla"], verbose=False,
        extra_cuda_cflags=["--offload-arch=gfx950", "-std=c++20", "-O3", "-[2D[K
"-mllvm --amdgpu-early-inline-all=true"],
    )
    _OK = True
except Exception as e:
    print(f"[custom_mla_v2] Build failed: {e}")
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

    # Optimize splits for MI355X CU count (304 CUs)
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
            print(f"[custom_mla_v2] Runtime error: {e}")

    return _asm_attention(data)
```

