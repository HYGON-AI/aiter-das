// SPDX-License-Identifier: MIT
//
// chunk_fwd_o entry: validates the ATen ABI, fills ChunkFwdOParams, and
// dispatches to dtype/head-dim specializations in csrc/fla/instances/.

#include "chunk_fwd_o.h"
#include "static_switch.h"

#include <ATen/hip/HIPContext.h>
#include <torch/all.h>

#include <algorithm>
#include <vector>

#define CHECK_DEVICE(x) TORCH_CHECK(x.is_cuda(), #x " must be on CUDA/HIP device")
#define CHECK_LAST_CONTIGUOUS(x) \
    TORCH_CHECK(x.stride(-1) == 1, #x " must have contiguous last dimension")

namespace {

using namespace FLA_NAMESPACE;

static inline int ceildiv(const int a, const int b)
{
    return (a + b - 1) / b;
}

static void set_common_params(
    ChunkFwdOParams &params,
    const at::Tensor &q,
    const at::Tensor &k,
    const at::Tensor &v,
    const at::Tensor &h,
    const std::optional<at::Tensor> &g,
    const std::optional<at::Tensor> &g_gamma,
    at::Tensor &o,
    const int B,
    const int T,
    const int H,
    const int Hg,
    const int K,
    const int V,
    const int BT,
    const int NT,
    const int N,
    const int grid_y,
    const float scale,
    void *cu_seqlens,
    int *chunk_offsets,
    const bool cu_seqlens_i64,
    const std::optional<at::Tensor> &chunk_indices,
    const bool is_varlen,
    const bool use_exp2,
    const bool transpose_state_layout)
{
    params = {};
    params.q_ptr = q.data_ptr();
    params.k_ptr = k.data_ptr();
    params.v_ptr = v.data_ptr();
    params.h_ptr = h.data_ptr();
    params.o_ptr = o.data_ptr();
    params.q_batch_stride = q.dim() == 4 ? q.stride(0) : 0;
    params.q_row_stride = q.dim() == 4 ? q.stride(1) : q.stride(0);
    params.q_head_stride = q.stride(-2);
    params.k_batch_stride = k.dim() == 4 ? k.stride(0) : 0;
    params.k_row_stride = k.dim() == 4 ? k.stride(1) : k.stride(0);
    params.k_head_stride = k.stride(-2);
    params.v_batch_stride = v.dim() == 4 ? v.stride(0) : 0;
    params.v_row_stride = v.dim() == 4 ? v.stride(1) : v.stride(0);
    params.v_head_stride = v.stride(-2);
    params.h_batch_stride = h.stride(0);
    params.h_chunk_stride = h.stride(1);
    params.h_head_stride = h.stride(2);
    params.o_batch_stride = o.dim() == 4 ? o.stride(0) : 0;
    params.o_row_stride = o.dim() == 4 ? o.stride(1) : o.stride(0);
    params.o_head_stride = o.stride(-2);

    params.use_g = g.has_value() && g.value().defined();
    if (params.use_g) {
        const auto &gt = g.value();
        params.g_ptr = gt.data_ptr();
        params.g_batch_stride = gt.dim() == 3 ? gt.stride(0) : 0;
        params.g_row_stride = gt.dim() == 3 ? gt.stride(1) : gt.stride(0);
    }
    params.use_g_gamma = g_gamma.has_value() && g_gamma.value().defined();
    if (params.use_g_gamma) {
        params.g_gamma_ptr = g_gamma.value().data_ptr();
    }

    params.B = B;
    params.T = T;
    params.H = H;
    params.Hg = Hg;
    params.K = K;
    params.V = V;
    params.BT = BT;
    params.NT = NT;
    params.N = N;
    params.grid_y = grid_y;
    params.scale = scale;
    params.cu_seqlens = cu_seqlens;
    params.chunk_offsets = chunk_offsets;
    params.cu_seqlens_i64 = cu_seqlens_i64;
    params.is_varlen = is_varlen;
    params.use_exp2 = use_exp2;
    params.transpose_state_layout = transpose_state_layout;

    params.use_chunk_indices =
        is_varlen && chunk_indices.has_value() && chunk_indices.value().defined();
    if (params.use_chunk_indices) {
        const auto &ci = chunk_indices.value();
        params.chunk_indices = ci.data_ptr();
        params.chunk_indices_i64 = ci.dtype() == torch::kInt64;
    }
}


////////////////////////////////////////////////////////////////////////////////////////////////////
// run_chunk_fwd_o
//
// Runtime dispatch mirrors chunk_gated_delta_rule_fwd: lift dtype and supported
// head dimensions, then forward to the linked specialization from instances/.
////////////////////////////////////////////////////////////////////////////////////////////////////
void run_chunk_fwd_o(
    FLA_NAMESPACE::ChunkFwdOParams &params, hipStream_t stream,
    bool use_safe_exp)
{
    FP16_SWITCH(!params.is_bf16, [&] {
        HEADDIM_KV_SWITCH(params.K, params.V, [&] {
            FLA_NAMESPACE::run_chunk_fwd_o_<elem_type, kHeadDim_K, kHeadDim_V>(
                params, stream, use_safe_exp);
        });
    });
}

static at::Tensor chunk_fwd_o_common(
    const at::Tensor &q,
    const at::Tensor &k,
    const at::Tensor &v,
    const at::Tensor &h,
    const std::optional<at::Tensor> &g,
    const std::optional<at::Tensor> &g_gamma,
    const double scale,
    const std::optional<at::Tensor> &cu_seqlens,
    const std::optional<at::Tensor> &chunk_indices,
    const int chunk_size,
    const bool use_exp2,
    const bool transpose_state_layout,
    const bool use_safe_exp,
    const bool ignore_g_gamma)
{
    const auto dtype = q.dtype();
    TORCH_CHECK(dtype == torch::kFloat16 || dtype == torch::kBFloat16,
                "chunk_fwd_o HIP supports fp16 and bf16");
    TORCH_CHECK(k.dtype() == dtype && v.dtype() == dtype && h.dtype() == dtype,
                "q, k, v, and h must have the same dtype");
    TORCH_CHECK(chunk_size == 64, "chunk_fwd_o HIP currently supports chunk_size == 64");
    TORCH_CHECK(q.dim() == 4 || q.dim() == 3, "q must be (B,T,Hg,K) or packed (T,Hg,K)");
    TORCH_CHECK(k.sizes() == q.sizes(), "k must have the same shape as q");
    TORCH_CHECK(v.dim() == q.dim(), "v must use the same rank as q");
    CHECK_DEVICE(q);
    CHECK_DEVICE(k);
    CHECK_DEVICE(v);
    CHECK_DEVICE(h);
    CHECK_LAST_CONTIGUOUS(q);
    CHECK_LAST_CONTIGUOUS(k);
    CHECK_LAST_CONTIGUOUS(v);
    CHECK_LAST_CONTIGUOUS(h);

    const bool is_varlen = cu_seqlens.has_value() && cu_seqlens.value().defined();
    TORCH_CHECK(!is_varlen || q.dim() == 4 || q.dim() == 3,
                "varlen chunk_fwd_o expects q rank 3 or 4");
    TORCH_CHECK(!is_varlen || q.size(0) == 1 || q.dim() == 3,
                "padded varlen chunk_fwd_o currently expects batch dimension 1");

    const int B = q.dim() == 4 ? int(q.size(0)) : 1;
    const int T = q.dim() == 4 ? int(q.size(1)) : int(q.size(0));
    const int Hg = int(q.size(-2));
    const int K = int(q.size(-1));
    const int H = int(v.size(-2));
    const int V = int(v.size(-1));
    TORCH_CHECK(K == 128 && V == 128,
                "chunk_fwd_o HIP currently supports K=128 and V=128");
    TORCH_CHECK(H % Hg == 0, "H must be divisible by Hg");
    if (q.dim() == 4) {
        TORCH_CHECK(v.sizes() == torch::IntArrayRef({B, T, H, V}),
                    "v must be (B,T,H,V)");
    } else {
        TORCH_CHECK(v.sizes() == torch::IntArrayRef({T, H, V}),
                    "packed v must be (T,H,V)");
    }

    if (g.has_value() && g.value().defined()) {
        const auto &gt = g.value();
        CHECK_DEVICE(gt);
        TORCH_CHECK(gt.dtype() == torch::kFloat32, "g must be float32");
        TORCH_CHECK(gt.stride(-1) == 1, "g must have contiguous head dimension");
    }
    const std::optional<at::Tensor> effective_g_gamma =
        ignore_g_gamma ? std::optional<at::Tensor>{} : g_gamma;
    if (effective_g_gamma.has_value() && effective_g_gamma.value().defined()) {
        const auto &gg = effective_g_gamma.value();
        CHECK_DEVICE(gg);
        TORCH_CHECK(gg.dtype() == torch::kFloat32, "g_gamma must be float32");
        TORCH_CHECK(gg.dim() == 1 && gg.size(0) == H, "g_gamma must have shape (H,)");
        TORCH_CHECK(gg.stride(0) == 1, "g_gamma must be contiguous");
    }

    if (transpose_state_layout) {
        TORCH_CHECK(h.dim() == 5 && h.size(2) == H && h.size(3) == V && h.size(4) == K,
                    "transpose_state_layout=true expects h shape (B,NT,H,V,K)");
    } else {
        TORCH_CHECK(h.dim() == 5 && h.size(2) == H && h.size(3) == K && h.size(4) == V,
                    "transpose_state_layout=false expects h shape (B,NT,H,K,V)");
    }

    int N = B;
    int NT = ceildiv(T, chunk_size);
    int grid_y = NT;
    at::Tensor chunk_offsets_dev;
    std::optional<at::Tensor> launch_chunk_indices = chunk_indices;
    void *cu_seqlens_d = nullptr;
    int *chunk_offsets_d = nullptr;
    bool cu_seqlens_i64 = false;

    if (is_varlen) {
        const auto &cu = cu_seqlens.value();
        CHECK_DEVICE(cu);
        TORCH_CHECK(cu.dim() == 1 && cu.size(0) >= 2,
                    "cu_seqlens must be a 1D tensor with at least two elements");
        TORCH_CHECK(cu.dtype() == torch::kInt32 || cu.dtype() == torch::kInt64,
                    "cu_seqlens must be int32 or int64");
        TORCH_CHECK(cu.stride(0) == 1, "cu_seqlens must be contiguous");
        N = int(cu.size(0) - 1);
        cu_seqlens_i64 = cu.dtype() == torch::kInt64;
        cu_seqlens_d = cu.data_ptr();

        const bool has_ci = chunk_indices.has_value() && chunk_indices.value().defined();
        if (has_ci) {
            const auto &ci = chunk_indices.value();
            CHECK_DEVICE(ci);
            TORCH_CHECK(ci.dim() == 2 && ci.size(1) == 2,
                        "chunk_indices must have shape (NT, 2)");
            TORCH_CHECK(ci.dtype() == torch::kInt32 || ci.dtype() == torch::kInt64,
                        "chunk_indices must be int32 or int64");
            NT = int(ci.size(0));
            grid_y = NT;
            if (N == 1) {
                launch_chunk_indices.reset();
            }
        } else {
            at::Tensor cu_cpu = cu.to(at::kCPU, at::kInt).contiguous();
            const int *cu_data = cu_cpu.data_ptr<int>();
            std::vector<int> offsets(N, 0);
            int total_chunks = 0;
            int max_chunks = 0;
            for (int i = 0; i < N; ++i) {
                const int seqlen = cu_data[i + 1] - cu_data[i];
                const int chunks = ceildiv(seqlen, chunk_size);
                offsets[i] = total_chunks;
                total_chunks += chunks;
                max_chunks = std::max(max_chunks, chunks);
            }
            NT = total_chunks;
            grid_y = max_chunks;
            chunk_offsets_dev = at::empty({N}, at::dtype(at::kInt).device(q.device()));
            chunk_offsets_dev.copy_(at::from_blob(offsets.data(), {N}, at::kInt));
            chunk_offsets_d = static_cast<int *>(chunk_offsets_dev.data_ptr());
        }
    }
    TORCH_CHECK(h.size(1) >= NT,
                "h chunk dimension is smaller than required NT=", NT);

    at::Tensor o = torch::empty_like(v);
    const bool is_bf16 = dtype == torch::kBFloat16;
    ChunkFwdOParams params;
    set_common_params(
        params, q, k, v, h, g, effective_g_gamma, o, B, T, H, Hg, K, V,
        chunk_size, NT, N, grid_y, static_cast<float>(scale), cu_seqlens_d,
        chunk_offsets_d, cu_seqlens_i64, launch_chunk_indices, is_varlen, use_exp2,
        transpose_state_layout);

    params.is_bf16 = is_bf16;

    const hipStream_t stream = at::hip::getCurrentHIPStream();
    run_chunk_fwd_o(params, stream, use_safe_exp);
    return o;
}

}  // namespace

at::Tensor chunk_fwd_o_vllm_hip_blockdim64(
    at::Tensor const &q,
    at::Tensor const &k,
    at::Tensor const &v,
    at::Tensor const &h,
    std::optional<at::Tensor> const &g,
    std::optional<at::Tensor> const &g_gamma,
    double const scale,
    std::optional<at::Tensor> const &cu_seqlens,
    std::optional<at::Tensor> const &chunk_indices,
    int const chunk_size,
    bool const use_exp2,
    bool const transpose_state_layout)
{
    return chunk_fwd_o_common(
        q, k, v, h, g, g_gamma, scale, cu_seqlens, chunk_indices,
        chunk_size, use_exp2, transpose_state_layout,
        /*use_safe_exp*/ false, /*ignore_g_gamma*/ false);
}

at::Tensor chunk_fwd_o_sglang_hip_blockdim64(
    at::Tensor const &q,
    at::Tensor const &k,
    at::Tensor const &v,
    at::Tensor const &h,
    std::optional<at::Tensor> const &g,
    std::optional<at::Tensor> const &g_gamma,
    double const scale,
    std::optional<at::Tensor> const &cu_seqlens,
    std::optional<at::Tensor> const &chunk_indices,
    int const chunk_size,
    bool const use_exp2,
    bool const transpose_state_layout)
{
    (void)g_gamma;
    (void)use_exp2;
    TORCH_CHECK(transpose_state_layout,
                "chunk_fwd_o_sglang_hip_blockdim64 only supports transpose_state_layout=true");
    return chunk_fwd_o_common(
        q, k, v, h, g, std::nullopt, scale, cu_seqlens, chunk_indices,
        chunk_size, /*use_exp2*/ false, /*transpose_state_layout*/ true,
        /*use_safe_exp*/ true, /*ignore_g_gamma*/ true);
}
