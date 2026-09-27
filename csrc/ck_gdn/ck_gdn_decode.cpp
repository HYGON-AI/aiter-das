// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
//
// CK GDN native adapter -- fused recurrent decode entry.
//
// Mirrors the argument plumbing of
// 3rdparty/composable_kernel/example_hcu/ck_tile/21_gdn/gdn_decode.cpp.
// Inputs are packed exactly like the example: q,k [tokens, h_qk, 128],
// v [tokens, h_v, 128], g/gk/gv/beta [tokens, h_v] and
// initial_state [sequences, h_v, 128, 128] fp32.
// CK headers must be parsed before torch: CK's GDN policy refers to
// ``detail::`` inside ``namespace ck_tile``, and torch injects a global
// ``::detail`` namespace that would otherwise make the lookup ambiguous.
#include "decode/gdn_decode_launch.hpp"

#include "ck_gdn_api.h"
#include "ck_gdn_common.h"

#include <ATen/hip/HIPContext.h>

#include <cmath>

namespace aiter {
namespace ck_gdn {
namespace {

constexpr int64_t kHeadDimCk = gdn_decode_example::kSupportedHeadDim;

int dtype_code(const torch::Tensor& t)
{
    switch(t.scalar_type())
    {
    case at::kHalf: return 0;
    case at::kBFloat16: return 1;
    case at::kFloat: return 2;
    default: TORCH_CHECK(false, "CK GDN decode supports float16, bfloat16 and float32 inputs"); return -1;
    }
}

void check_packed(const torch::Tensor& x, const char* name)
{
    TORCH_CHECK(x.is_cuda(), name, " must be a CUDA/HIP tensor");
    TORCH_CHECK(x.is_contiguous(), name, " must be contiguous");
    TORCH_CHECK(x.dim() == 3 && x.size(2) == kHeadDimCk,
                name, " must be [tokens, heads, 128]");
    TORCH_CHECK(x.scalar_type() == at::kHalf || x.scalar_type() == at::kBFloat16,
                name, " must be float16 or bfloat16");
}

void check_optional_vector(const std::optional<torch::Tensor>& x,
                           const char* name,
                           int64_t rows,
                           int64_t cols)
{
    if(!x.has_value())
        return;
    TORCH_CHECK(x->is_cuda() && x->is_contiguous(), name, " must be contiguous on device");
    TORCH_CHECK(x->numel() == rows * cols,
                name, " must have ", rows * cols, " elements");
}

} // namespace

std::vector<torch::Tensor> decode(const torch::Tensor& q,
                                  const torch::Tensor& k,
                                  const torch::Tensor& v,
                                  const std::optional<torch::Tensor>& g,
                                  const torch::Tensor& beta,
                                  const std::optional<torch::Tensor>& gk,
                                  const std::optional<torch::Tensor>& gv,
                                  const std::optional<torch::Tensor>& a_log,
                                  const std::optional<torch::Tensor>& dt_bias,
                                  const std::optional<torch::Tensor>& initial_state,
                                  const std::optional<torch::Tensor>& cu_seqlens,
                                  const std::optional<double>& scale,
                                  bool use_g,
                                  bool use_gk,
                                  bool use_gv,
                                  bool beta_headwise,
                                  bool use_qk_l2norm,
                                  bool use_exp2,
                                  bool transpose_state,
                                  bool gate_in_kernel,
                                  bool has_dt_bias,
                                  bool store_final_state)
{
    check_packed(q, "q");
    check_packed(k, "k");
    check_packed(v, "v");

    const int64_t total_tokens = q.size(0);
    const int64_t h_qk         = q.size(1);
    const int64_t h_v          = v.size(1);
    TORCH_CHECK(k.size(0) == total_tokens && k.size(1) == h_qk,
                "k must be [tokens, h_qk, 128]");
    TORCH_CHECK(v.size(0) == total_tokens, "v must have the same token count as q");
    TORCH_CHECK(k.scalar_type() == q.scalar_type() && v.scalar_type() == q.scalar_type(),
                "q, k and v must share a dtype");
    TORCH_CHECK(h_qk > 0 && h_v > 0 && h_v % h_qk == 0,
                "h_v must be a positive multiple of h_qk");

    // Sequence layout: cu_seqlens selects packed varlen, otherwise the input is
    // batch * time with the batch dimension laid out outermost.
    int64_t sequences = 1;
    int64_t batch     = 1;
    int64_t time      = total_tokens;
    bool    variable_length = cu_seqlens.has_value();
    if(variable_length)
    {
        const auto& cu = *cu_seqlens;
        TORCH_CHECK(cu.is_cuda() && cu.is_contiguous() && cu.scalar_type() == at::kLong,
                    "cu_seqlens must be a contiguous int64 device tensor");
        TORCH_CHECK(cu.dim() == 1 && cu.numel() >= 2, "cu_seqlens must be [sequences + 1]");
        sequences = cu.numel() - 1;
        const auto host = cu.to(torch::kCPU);
        const auto* ptr = host.data_ptr<int64_t>();
        TORCH_CHECK(ptr[0] == 0, "cu_seqlens must start at 0");
        TORCH_CHECK(ptr[sequences] == total_tokens,
                    "cu_seqlens must end at the packed token count");
        for(int64_t i = 0; i < sequences; ++i)
            TORCH_CHECK(ptr[i + 1] > ptr[i], "sequence lengths must be positive");
        // The kernel walks [bos, eos) per sequence and ignores `time` here.
        batch = 1;
        time  = total_tokens;
    }
    TORCH_CHECK(sequences * h_v <= (1LL << 31), "decode grid is too large");

    TORCH_CHECK(beta.is_cuda() && beta.is_contiguous(), "beta must be contiguous on device");
    TORCH_CHECK(beta.numel() == total_tokens * h_v,
                "beta must be [tokens, h_v]");
    check_optional_vector(g, "g", total_tokens, h_v);
    check_optional_vector(gk, "gk", total_tokens, h_v);
    check_optional_vector(gv, "gv", total_tokens, h_v);
    check_optional_vector(a_log, "a_log", 1, h_v);
    check_optional_vector(dt_bias, "dt_bias", 1, h_v);

    TORCH_CHECK(!use_g || g.has_value(), "g is required when use_g is enabled");
    TORCH_CHECK(!use_gk || gk.has_value(), "gk is required when use_gk is enabled");
    TORCH_CHECK(!use_gv || gv.has_value(), "gv is required when use_gv is enabled");
    TORCH_CHECK(!gate_in_kernel || a_log.has_value(),
                "a_log is required when gate_in_kernel is enabled");
    TORCH_CHECK(!has_dt_bias || gate_in_kernel,
                "has_dt_bias is only meaningful together with gate_in_kernel");

    if(initial_state.has_value())
    {
        const auto& state = *initial_state;
        TORCH_CHECK(state.is_cuda() && state.is_contiguous() &&
                        state.scalar_type() == at::kFloat,
                    "initial_state must be a contiguous float32 device tensor");
        TORCH_CHECK(state.numel() == sequences * h_v * kHeadDimCk * kHeadDimCk,
                    "initial_state must be [sequences, h_v, 128, 128]");
    }

    const bool use_initial_state = initial_state.has_value();
    const auto output = torch::empty({total_tokens, h_v, kHeadDimCk}, q.options());
    auto final_state = store_final_state
                           ? torch::empty({sequences, h_v, kHeadDimCk, kHeadDimCk},
                                          q.options().dtype(at::kFloat))
                           : torch::Tensor();

    const float resolved_scale =
        (!scale.has_value() || *scale == 0.0)
            ? static_cast<float>(1.0 / std::sqrt(static_cast<double>(kHeadDimCk)))
            : static_cast<float>(*scale);

    const int f32 = gdn_tensor_dtype_code(GdnTensorDtype::Float32);

    GdnFusedRecurrentKargs args{};
    args.q = q.data_ptr();
    args.k = k.data_ptr();
    args.v = v.data_ptr();
    args.g  = g.has_value() ? g->data_ptr() : nullptr;
    args.gk = gk.has_value() ? gk->data_ptr() : nullptr;
    args.gv = gv.has_value() ? gv->data_ptr() : nullptr;
    args.beta   = beta.data_ptr();
    args.a_log  = a_log.has_value() ? a_log->data_ptr() : nullptr;
    args.dt_bias = dt_bias.has_value() ? dt_bias->data_ptr() : nullptr;
    args.initial_state = initial_state.has_value() ? initial_state->data_ptr<float>() : nullptr;
    args.cu_seqlens    = variable_length ? cu_seqlens->data_ptr<int64_t>() : nullptr;
    args.output        = output.data_ptr();
    args.final_state   = store_final_state ? final_state.data_ptr<float>() : nullptr;

    args.batch       = static_cast<ck_tile::index_t>(batch);
    args.time        = static_cast<ck_tile::index_t>(time);
    args.qk_heads    = static_cast<ck_tile::index_t>(h_qk);
    args.value_heads = static_cast<ck_tile::index_t>(h_v);
    args.key_dim     = static_cast<ck_tile::index_t>(kHeadDimCk);
    args.value_dim   = static_cast<ck_tile::index_t>(kHeadDimCk);
    args.sequences   = static_cast<ck_tile::index_t>(sequences);
    args.scale       = resolved_scale;

    args.g_dtype       = g.has_value() ? dtype_code(*g) : f32;
    args.gk_dtype      = gk.has_value() ? dtype_code(*gk) : f32;
    args.gv_dtype      = gv.has_value() ? dtype_code(*gv) : f32;
    args.beta_dtype    = dtype_code(beta);
    args.a_log_dtype   = a_log.has_value() ? dtype_code(*a_log) : f32;
    args.dt_bias_dtype = dt_bias.has_value() ? dtype_code(*dt_bias) : f32;

    args.use_g            = use_g && g.has_value();
    args.use_gk           = use_gk && gk.has_value();
    args.use_gv           = use_gv && gv.has_value();
    args.beta_headwise    = beta_headwise;
    args.use_initial_state = use_initial_state;
    args.store_final_state = store_final_state;
    args.use_qk_l2norm    = use_qk_l2norm;
    args.use_exp2         = use_exp2;
    args.transpose_state  = transpose_state;
    args.variable_length  = variable_length;
    args.gate_in_kernel   = gate_in_kernel;
    args.has_dt_bias      = has_dt_bias;

    const hipStream_t stream = at::hip::getCurrentHIPStream();
    if(q.scalar_type() == at::kBFloat16)
        gdn_decode_example::launch_bf16(args, stream);
    else
        gdn_decode_example::launch_fp16(args, stream);

    return {output, final_state};
}

} // namespace ck_gdn
} // namespace aiter
