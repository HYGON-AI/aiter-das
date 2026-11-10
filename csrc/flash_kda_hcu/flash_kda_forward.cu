// SPDX-License-Identifier: MIT

// FlashKDA 主机侧统一前向入口。
// 负责参数校验、输出与 workspace 准备，并在当前 HIP stream 上
// 调度 K1、K2 或分段计算；同时提供 workspace 容量查询。
// 各 GPU kernel 的计算与流水线实现在 k1/、k2/ 目录。

#ifndef __HIP_DEVICE_COMPILE__

#include "flash_kda_forward.h"

#include <ATen/hip/HIPContext.h>
#include <ATen/hip/impl/HIPGuardImplMasqueradingAsCUDA.h>
#include <c10/hip/HIPException.h>
#include <hip/hip_runtime.h>

#include <algorithm>
#include <array>
#include <cmath>
#include <string>

#include "flash_kda_launch.h"

namespace
{

    constexpr int64_t kKeyDim = 128;
    constexpr int64_t kValueDim = 128;

    [[noreturn]] void invalid(const std::string &message)
    {
        throw std::invalid_argument(message);
    }

    struct Span
    {
        const void *ptr;
        size_t bytes;
    };

    bool overlap(const Span &a, const Span &b)
    {
        const auto *a0 = static_cast<const unsigned char *>(a.ptr);
        const auto *b0 = static_cast<const unsigned char *>(b.ptr);
        return a0 < b0 + b.bytes && b0 < a0 + a.bytes;
    }

    // 输出之间、输出与只读输入之间各查一次；固定小集合用栈数组，不建堆容器。
    template <size_t NIn, size_t NOut>
    void check_overlap(const std::array<Span, NIn> &inputs, size_t n_inputs,
                       const std::array<Span, NOut> &outputs, size_t n_outputs)
    {
        for (size_t i = 0; i < n_outputs; ++i)
        {
            for (size_t j = i + 1; j < n_outputs; ++j)
            {
                if (overlap(outputs[i], outputs[j]))
                {
                    invalid("FlashKDA output buffers must not overlap each other");
                }
            }
            for (size_t k = 0; k < n_inputs; ++k)
            {
                if (overlap(outputs[i], inputs[k]))
                {
                    invalid("FlashKDA output buffer overlaps an input tensor");
                }
            }
        }
    }

    // 架构名按设备缓存（只读属性；不缓存输入、stream 或环境选择）。
    const std::string &arch_name(int device)
    {
        static std::array<std::string, 64> cache{};
        static std::array<bool, 64> ready{};
        static std::string unknown;
        if (device < 0 || device >= 64)
        {
            return unknown;
        }
        if (!ready[device])
        {
            hipDeviceProp_t properties;
            C10_HIP_CHECK(hipGetDeviceProperties(&properties, device));
            cache[device] = properties.gcnArchName;
            ready[device] = true;
        }
        return cache[device];
    }

    torch::Tensor require_contiguous(torch::Tensor tensor, const char *name, bool normalize)
    {
        if (tensor.is_contiguous())
        {
            return tensor;
        }
        if (!normalize)
        {
            invalid(std::string(name) + " must be contiguous in the preallocated entry");
        }
        return tensor.contiguous();
    }

    void check_device(const torch::Tensor &tensor, const torch::Device &device, const char *name)
    {
        if (!tensor.is_cuda() || tensor.device() != device)
        {
            invalid(std::string(name) + " must be a CUDA tensor on the input device");
        }
    }

} // namespace

std::tuple<torch::Tensor, torch::Tensor> kda_forward(
    const torch::Tensor &q_in, const torch::Tensor &k_in, const torch::Tensor &v_in,
    const torch::Tensor &g_in, const torch::Tensor &beta_in,
    const std::optional<torch::Tensor> &A_log_in, const std::optional<torch::Tensor> &dt_bias_in,
    const std::optional<double> &scale_opt, const std::optional<double> &lower_bound_opt,
    const std::optional<torch::Tensor> &initial_state_in, bool output_final_state,
    const std::optional<at::ScalarType> &state_dtype_opt,
    const std::optional<torch::Tensor> &cu_seqlens_in, int64_t features,
    const std::optional<int64_t> &chunk_size_opt, bool allow_fallback, bool normalize_inputs,
    const std::optional<torch::Tensor> &out_in, const std::optional<torch::Tensor> &final_state_in,
    const std::optional<torch::Tensor> &workspace_in)
{
    const auto unsupported = std::make_tuple(torch::Tensor(), torch::Tensor());

    // ---- 1. 通用公开契约（合法但 HCU 不支持的输入必须还能回退）----
    if (q_in.dim() != 4 || k_in.dim() != 4 || v_in.dim() != 4 || g_in.dim() != 4 ||
        beta_in.dim() != 3)
    {
        invalid("q/k/v/g must be 4D tensors and beta must be 3D");
    }
    const int64_t B = q_in.size(0);
    const int64_t T = q_in.size(1);
    const int64_t H = q_in.size(2);
    const int64_t K = q_in.size(3);
    const int64_t HV = v_in.size(2);
    if (B <= 0 || H <= 0)
    {
        invalid("B and H must be positive");
    }
    if (q_in.sizes() != k_in.sizes())
    {
        invalid("q and k must have the same shape");
    }
    if (K > 256)
    {
        invalid("key head dim must be <= 256");
    }
    if (HV <= 0 || HV % H != 0)
    {
        invalid("num_v_heads must be a positive multiple of num_k_heads");
    }
    // R02：v 的 B/T 必须与 q 一致，否则 kernel 按 q 的长度会读写越界。
    // V 维度不在此限制：V != 128 属"合法但 HCU 不支持"，必须允许 Triton 回退。
    if (v_in.size(0) != B || v_in.size(1) != T)
    {
        invalid("v shape must be [B,T,H,V] matching q's B and T");
    }
    if (g_in.dim() != 4 || g_in.size(0) != B || g_in.size(1) != T || g_in.size(2) != HV ||
        g_in.size(3) != K)
    {
        invalid("g shape must be [B,T,H,K]");
    }
    if (beta_in.size(0) != B || beta_in.size(1) != T || beta_in.size(2) != HV)
    {
        invalid("beta shape must be [B,T,H]");
    }
    if (chunk_size_opt.has_value() && chunk_size_opt.value() != 32 &&
        chunk_size_opt.value() != 64)
    {
        // 与 Triton 入口一致：{None, 32, 64} 之外的 chunk_size 属通用非法。
        invalid("chunk_size must be None, 32 or 64");
    }
    const bool is_varlen = cu_seqlens_in.has_value() && cu_seqlens_in->defined();
    if (is_varlen && B != 1)
    {
        invalid("varlen mode requires B=1");
    }
    if (T <= 0 && !is_varlen)
    {
        invalid("T must be positive");
    }
    if (final_state_in.has_value() && final_state_in->defined() && !output_final_state)
    {
        invalid("final_state was provided but output_final_state=False");
    }
    const double scale = scale_opt.has_value() ? scale_opt.value()
                                              : std::pow(static_cast<double>(K), -0.5);
    if (!(scale > 0.0))
    {
        invalid("scale must be positive");
    }
    const double lower_bound = lower_bound_opt.has_value() ? lower_bound_opt.value() : -5.0;

    // ---- 2. 连续化（兼容模式复制并保活 owner；严格模式拒绝）----
    torch::Tensor q = require_contiguous(q_in, "q", normalize_inputs);
    torch::Tensor k = require_contiguous(k_in, "k", normalize_inputs);
    torch::Tensor v = require_contiguous(v_in, "v", normalize_inputs);
    torch::Tensor g = require_contiguous(g_in, "g", normalize_inputs);
    torch::Tensor beta = require_contiguous(beta_in, "beta", normalize_inputs);
    torch::Tensor A_log = (A_log_in.has_value() && A_log_in->defined())
                              ? require_contiguous(*A_log_in, "A_log", normalize_inputs)
                              : torch::Tensor();
    torch::Tensor dt_bias = (dt_bias_in.has_value() && dt_bias_in->defined())
                                ? require_contiguous(*dt_bias_in, "dt_bias", normalize_inputs)
                                : torch::Tensor();
    torch::Tensor cu_seqlens = is_varlen
                                   ? require_contiguous(*cu_seqlens_in, "cu_seqlens",
                                                        normalize_inputs)
                                   : torch::Tensor();
    torch::Tensor initial_state = (initial_state_in.has_value() && initial_state_in->defined())
                                      ? require_contiguous(*initial_state_in, "initial_state",
                                                           normalize_inputs)
                                      : torch::Tensor();

    // ---- 3. HCU 准入（此后才开始要求 HCU 专属条件）----
    if (!q.is_cuda() || !k.is_cuda() || !v.is_cuda() || !g.is_cuda() || !beta.is_cuda())
    {
        if (allow_fallback)
        {
            return unsupported;
        }
        throw std::runtime_error("FlashKDA HCU requires CUDA/HIP tensors");
    }
    const auto device = q.device();
    // 必备位必须全开，且不允许出现可选位与必备位之外的任何位
    // （disable_recompute 与未知位都落在 ~kHcuAllowedFeatures 里）。
    const bool feature_ok =
        (features & flash_kda::kHcuRequiredFeatures) == flash_kda::kHcuRequiredFeatures &&
        (features & ~flash_kda::kHcuAllowedFeatures) == 0;
    // 初态与终态共用同一个布局选择：K=V=128 时形状无法区分两种布局，
    // 必须由调用方显式给出，不能从 shape 猜测。
    const bool state_v_first = (features & flash_kda::kFeatureStateVFirst) != 0;
    // 两种布局的 state 形状分帧不同：KV 是 [N,H,K,V]，VK 是 [N,H,V,K]。
    const int64_t state_dim_outer = state_v_first ? kValueDim : kKeyDim;
    const int64_t state_dim_inner = state_v_first ? kKeyDim : kValueDim;
    const bool supported =
        feature_ok &&
        q.scalar_type() == at::kBFloat16 && k.scalar_type() == at::kBFloat16 &&
        v.scalar_type() == at::kBFloat16 && g.scalar_type() == at::kBFloat16 &&
        (beta.scalar_type() == at::kFloat || beta.scalar_type() == at::kBFloat16) &&
        K == kKeyDim && HV == H &&
        v_in.size(3) == kValueDim &&
        (!chunk_size_opt.has_value() || chunk_size_opt.value() == 32) &&
        arch_name(q.get_device()).rfind("gfx936", 0) == 0;
    if (!supported)
    {
        if (allow_fallback)
        {
            return unsupported;
        }
        throw std::runtime_error("FlashKDA HCU unsupported: dtype/shape/arch");
    }

    // ---- 4. HCU 专属条件（R01：同设备、形状、连续性；A_log 必需）----
    check_device(k, device, "k");
    check_device(v, device, "v");
    check_device(g, device, "g");
    check_device(beta, device, "beta");
    if (!A_log.defined())
    {
        invalid("A_log must be provided");
    }
    check_device(A_log, device, "A_log");
    if (A_log.scalar_type() != at::kFloat || A_log.dim() != 1 || A_log.numel() != H)
    {
        invalid("A_log must be FP32 [H]");
    }
    const bool has_bias = dt_bias.defined();
    if (has_bias)
    {
        check_device(dt_bias, device, "dt_bias");
        // 公开契约是 FP32 [H*128]（也可传 [H,128]）；两者 numel 相同，按连续指针使用。
        const bool flat_ok = dt_bias.dim() == 1 && dt_bias.numel() == H * kKeyDim;
        const bool matrix_ok = dt_bias.dim() == 2 && dt_bias.size(0) == H &&
                               dt_bias.size(1) == kKeyDim;
        if (dt_bias.scalar_type() != at::kFloat || !(flat_ok || matrix_ok))
        {
            invalid("dt_bias must be FP32 [H*128] or [H,128]");
        }
    }
    if (!(lower_bound >= -5.0 && lower_bound < 0.0))
    {
        invalid("lower_bound must be in [-5,0)");
    }

    // ---- 5. state dtype：显式与推断都只允许 FP32/BF16；冲突按公开契约报 ValueError ----
    at::ScalarType resolved_state = at::kFloat;
    const bool has_initial = initial_state.defined();
    if (has_initial)
    {
        resolved_state = initial_state.scalar_type();
    }
    if (state_dtype_opt.has_value())
    {
        if (state_dtype_opt.value() != at::kFloat && state_dtype_opt.value() != at::kBFloat16)
        {
            throw pybind11::type_error("state_dtype must be FP32 or BF16");
        }
        if (has_initial && state_dtype_opt.value() != resolved_state)
        {
            invalid("state_dtype conflicts with initial_state dtype");
        }
        resolved_state = state_dtype_opt.value();
    }
    if (resolved_state != at::kFloat && resolved_state != at::kBFloat16)
    {
        throw pybind11::type_error("state dtype must be FP32 or BF16");
    }
    const bool store_final = output_final_state;

    // ---- 6. 布局（含 launcher / MUBUF 上限）----
    int64_t sequence_count = B;
    if (is_varlen)
    {
        if (cu_seqlens.dim() != 1 || cu_seqlens.numel() < 2)
        {
            invalid("cu_seqlens must be 1-D with N+1 entries");
        }
        if (cu_seqlens.scalar_type() != at::kLong && cu_seqlens.scalar_type() != at::kInt)
        {
            invalid("cu_seqlens must be INT32 or INT64");
        }
        check_device(cu_seqlens, device, "cu_seqlens");
        sequence_count = cu_seqlens.numel() - 1;
    }
    const flash_kda::WorkspaceLayout layout = flash_kda::make_workspace_layout(
        B, T, H, sequence_count, is_varlen, flash_kda::force_plain_from_env());

    // ---- 7. scratch / out / final_state（None 与空 Tensor 语义分开）----
    torch::Tensor workspace;
    if (workspace_in.has_value() && workspace_in->defined())
    {
        workspace = *workspace_in;
        check_device(workspace, device, "workspace");
        if (!workspace.is_contiguous() || workspace.scalar_type() != at::kByte)
        {
            invalid("workspace must be a contiguous uint8 tensor");
        }
        if (static_cast<size_t>(workspace.numel()) < layout.total_bytes)
        {
            invalid("workspace capacity is smaller than required");
        }
        if (reinterpret_cast<uintptr_t>(workspace.data_ptr()) % flash_kda::kAlignBytes != 0)
        {
            invalid("workspace base address must be 16B aligned");
        }
    }
    else
    {
        workspace = torch::empty({static_cast<int64_t>(layout.total_bytes)},
                                 torch::TensorOptions().dtype(at::kByte).device(device));
    }
    const int64_t state_batch = is_varlen ? sequence_count : B;
    torch::Tensor out;
    if (out_in.has_value() && out_in->defined())
    {
        out = *out_in;
        check_device(out, device, "out");
        if (!out.is_contiguous() || out.scalar_type() != at::kBFloat16 ||
            !(out.sizes() == v.sizes()))
        {
            invalid("out must be contiguous CUDA BF16 with v's shape");
        }
    }
    else
    {
        out = torch::empty_like(v);
    }
    torch::Tensor final_state;
    if (store_final)
    {
        if (final_state_in.has_value() && final_state_in->defined())
        {
            final_state = *final_state_in;
            check_device(final_state, device, "final_state");
            if (!final_state.is_contiguous() || final_state.scalar_type() != resolved_state ||
                !(final_state.sizes() ==
                  std::vector<int64_t>({state_batch, H, state_dim_outer, state_dim_inner})))
            {
                invalid(state_v_first
                            ? "final_state must be contiguous [N,H,V,K] with the resolved dtype"
                            : "final_state must be contiguous [N,H,K,V] with the resolved dtype");
            }
        }
        else
        {
            final_state = torch::empty({state_batch, H, state_dim_outer, state_dim_inner},
                                       torch::TensorOptions().dtype(resolved_state).device(device));
        }
    }
    if (has_initial)
    {
        check_device(initial_state, device, "initial_state");
        if (!initial_state.is_contiguous() || initial_state.scalar_type() != resolved_state ||
            !(initial_state.sizes() ==
              std::vector<int64_t>({state_batch, H, state_dim_outer, state_dim_inner})))
        {
            invalid(state_v_first
                        ? "initial_state must be contiguous [N,H,V,K] with the resolved dtype"
                        : "initial_state must be contiguous [N,H,K,V] with the resolved dtype");
        }
    }

    // ---- 8. 区间重叠（只读侧纳入 A_log/dt_bias/cu_seqlens）----
    std::array<Span, 9> inputs{};
    size_t n_inputs = 0;
    for (const auto *tensor : {&q, &k, &v, &g, &beta})
    {
        inputs[n_inputs++] = Span{tensor->data_ptr(), static_cast<size_t>(tensor->nbytes())};
    }
    inputs[n_inputs++] = Span{A_log.data_ptr(), static_cast<size_t>(A_log.nbytes())};
    if (has_bias)
    {
        inputs[n_inputs++] = Span{dt_bias.data_ptr(), static_cast<size_t>(dt_bias.nbytes())};
    }
    if (has_initial)
    {
        inputs[n_inputs++] = Span{initial_state.data_ptr(),
                                  static_cast<size_t>(initial_state.nbytes())};
    }
    if (is_varlen)
    {
        inputs[n_inputs++] = Span{cu_seqlens.data_ptr(),
                                  static_cast<size_t>(cu_seqlens.nbytes())};
    }
    std::array<Span, 3> outputs{};
    size_t n_outputs = 0;
    outputs[n_outputs++] = Span{out.data_ptr(), static_cast<size_t>(out.nbytes())};
    if (store_final)
    {
        outputs[n_outputs++] = Span{final_state.data_ptr(),
                                    static_cast<size_t>(final_state.nbytes())};
    }
    outputs[n_outputs++] = Span{workspace.data_ptr(), static_cast<size_t>(workspace.nbytes())};
    check_overlap(inputs, n_inputs, outputs, n_outputs);

    // ---- 9. raw 参数与启动 ----
    flash_kda::detail::ForwardParams params;
    params.batch = B;
    params.tokens = T;
    params.heads = H;
    params.sequence_count = sequence_count;
    params.head_stride_chunks = layout.head_stride_chunks;
    params.workspace_chunks = layout.workspace_chunks;
    params.chunks_per_segment = layout.chunks_per_segment;
    params.segment_count = layout.segment_count;
    params.is_varlen = is_varlen;
    params.tail = !is_varlen && (T % 16) != 0;
    params.has_bias = has_bias;
    params.beta_bf16 = beta.scalar_type() == at::kBFloat16;
    params.write_beta_fp32 = true;
    params.has_initial = has_initial;
    params.store_final = store_final;
    params.state_bf16 = resolved_state == at::kBFloat16;
    params.state_v_first = state_v_first;
    params.scale = static_cast<float>(scale);
    params.lower_bound = static_cast<float>(lower_bound);
    params.q = q.data_ptr();
    params.k = k.data_ptr();
    params.v = v.data_ptr();
    params.g = g.data_ptr();
    params.beta = beta.data_ptr();
    params.A_log = A_log.data_ptr<float>();
    params.dt_bias = has_bias ? dt_bias.data_ptr<float>() : nullptr;
    params.initial_state = has_initial ? initial_state.data_ptr() : nullptr;
    params.out = out.data_ptr();
    params.final_state = store_final ? final_state.data_ptr() : nullptr;
    if (is_varlen)
    {
        if (cu_seqlens.scalar_type() == at::kInt)
        {
            params.cu_int32 = true;
            params.cu_seqlens32 = cu_seqlens.data_ptr<int32_t>();
        }
        else
        {
            params.cu_seqlens = cu_seqlens.data_ptr<int64_t>();
        }
    }

    auto *base = static_cast<unsigned char *>(workspace.data_ptr());
    flash_kda::detail::WorkspaceViews views;
    const auto at_offset = [&](const flash_kda::Region &region) -> unsigned char *
    { return region.bytes == 0 ? nullptr : base + region.offset; };
    views.kdqd = reinterpret_cast<unsigned short *>(at_offset(layout.kdqd));
    views.krgt = reinterpret_cast<unsigned short *>(at_offset(layout.krgt));
    views.inv = reinterpret_cast<unsigned short *>(at_offset(layout.inv));
    views.mqk = reinterpret_cast<unsigned short *>(at_offset(layout.mqk));
    views.beta_sigmoid = reinterpret_cast<float *>(at_offset(layout.beta_sigmoid));
    views.chunk_info = reinterpret_cast<int64_t *>(at_offset(layout.chunk_info));
    views.sequence_info = reinterpret_cast<int64_t *>(at_offset(layout.sequence_info));
    views.segment_transition = at_offset(layout.segment_transition);
    views.segment_update = at_offset(layout.segment_update);
    views.segment_initial_states = at_offset(layout.segment_initial_states);

    const at::hip::OptionalHIPGuardMasqueradingAsCUDA guard(device);
    const hipStream_t stream = at::hip::getCurrentHIPStream(q.get_device());
    if (is_varlen)
    {
        flash_kda::detail::launch_varlen_metadata(params, views, stream);
        flash_kda::detail::launch_k1(params, views, stream);
        flash_kda::detail::launch_k2(params, views, stream);
    }
    else if (layout.path == flash_kda::KdaPath::Segmented)
    {
        flash_kda::detail::launch_k1(params, views, stream);
        flash_kda::detail::launch_segment_affine(params, views, stream);
        flash_kda::detail::launch_segment_scan(params, views, stream);
        flash_kda::detail::launch_segment_replay(params, views, stream);
    }
    else
    {
        flash_kda::detail::launch_k1(params, views, stream);
        flash_kda::detail::launch_k2(params, views, stream);
    }
    C10_HIP_CHECK(hipGetLastError());

    return std::make_tuple(out, store_final ? final_state : torch::Tensor());
}

// ---------------------------------------------------------------------------
// 冷路径容量查询：与 forward 共用 make_workspace_layout（含 launcher 上限）。
// ---------------------------------------------------------------------------
int64_t kda_workspace_bytes(int64_t batch, int64_t tokens, int64_t heads,
                            int64_t sequence_count, bool is_varlen)
{
    const flash_kda::WorkspaceLayout layout =
        flash_kda::make_workspace_layout(batch, tokens, heads, sequence_count, is_varlen,
                                         flash_kda::force_plain_from_env());
    return static_cast<int64_t>(layout.total_bytes);
}

int64_t kda_segment_chunks(int64_t batch, int64_t tokens, int64_t heads)
{
    if (flash_kda::force_plain_from_env())
    {
        return 0;
    }
    return flash_kda::segment_chunks_for(batch, tokens, heads);
}

#endif // __HIP_DEVICE_COMPILE__
