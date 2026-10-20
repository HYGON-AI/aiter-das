// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
//
// CK GDN native adapter -- prefill entry.
//
// Mirrors the argument plumbing of
// 3rdparty/composable_kernel/example_hcu/ck_tile/21_gdn/gdn_prefill.cpp while
// replacing the example's DeviceMem allocations with one flat caller-provided
// workspace (see ck_gdn_common.h).
//
// Differences from the example that are intentional and documented:
//   * a single-sequence varlen request is normalised to the fixed-length path
//     (identical math, and it avoids relying on chunk_offsets that CK only
//     materialises for multi-sequence varlen);
//   * v_new is always materialised because CK's output stage consumes it. The
//     A-layer entry returns {output, final_state} only.
// CK headers must be parsed before torch: CK's GDN headers refer to
// ``detail::`` inside their own namespaces, and torch injects a global
// ``::detail`` that would otherwise make the lookup ambiguous.
#include "prefill/gdn_prefill_launch.hpp"

#include "ck_gdn_api.h"
#include "ck_gdn_common.h"

#include <ATen/hip/HIPContext.h>

#include <cmath>

namespace aiter {
namespace ck_gdn {
namespace {

constexpr int64_t kHeadDimCk   = gdn_example::kSupportedHeadDim;
constexpr int64_t kChunkSizeCk = gdn_example::kChunkSize;

void check_packed_half(const torch::Tensor& x, const char* name)
{
    TORCH_CHECK(x.is_cuda(), name, " must be a CUDA/HIP tensor");
    TORCH_CHECK(x.is_contiguous(), name, " must be contiguous");
    TORCH_CHECK(x.scalar_type() == at::kHalf || x.scalar_type() == at::kBFloat16,
                name, " must be float16 or bfloat16");
    TORCH_CHECK(x.dim() == 3 && x.size(2) == kHeadDimCk,
                name, " must be [tokens, heads, 128]");
}

void check_optional_f32(const std::optional<torch::Tensor>& x, const char* name)
{
    if(!x.has_value())
        return;
    TORCH_CHECK(x->is_cuda(), name, " must be a CUDA/HIP tensor");
    TORCH_CHECK(x->is_contiguous(), name, " must be contiguous");
    TORCH_CHECK(x->scalar_type() == at::kFloat, name, " must be float32");
}

// Metadata shared by the size query and the launch entry.
struct Meta
{
    int64_t t          = 0;
    int64_t h_qk       = 0;
    int64_t h_v        = 0;
    int64_t sequences  = 1;
    int64_t num_chunks = 0;
    bool    varlen     = false;
    bool    is_bf16    = true;
};

Meta derive_meta(const torch::Tensor& q,
                 const torch::Tensor& v,
                 const std::optional<torch::Tensor>& cu_seqlens)
{
    check_packed_half(q, "q");
    check_packed_half(v, "v");

    Meta meta;
    meta.t    = q.size(0);
    meta.h_qk = q.size(1);
    meta.h_v  = v.size(1);
    meta.is_bf16 = q.scalar_type() == at::kBFloat16;

    TORCH_CHECK(v.size(0) == meta.t, "v must have the same token count as q");
    TORCH_CHECK(v.scalar_type() == q.scalar_type(), "q and v must share a dtype");
    TORCH_CHECK(meta.h_qk > 0 && meta.h_v > 0, "head counts must be positive");
    TORCH_CHECK(meta.h_v % meta.h_qk == 0, "h_v must be a multiple of h_qk");
    const int64_t ratio = meta.h_v / meta.h_qk;
    TORCH_CHECK(ratio == 1 || ratio == 2 || ratio == 4,
                "CK GDN supports h_v / h_qk in {1,2,4}");

    if(cu_seqlens.has_value())
    {
        const auto& cu = *cu_seqlens;
        TORCH_CHECK(cu.is_cuda() && cu.is_contiguous(), "cu_seqlens must be contiguous on device");
        TORCH_CHECK(cu.scalar_type() == at::kLong, "CK GDN requires int64 cu_seqlens");
        TORCH_CHECK(cu.dim() == 1 && cu.numel() >= 2, "cu_seqlens must be [sequences + 1]");
        meta.sequences = cu.numel() - 1;

        const auto host = cu.to(torch::kCPU);
        const auto* ptr = host.data_ptr<int64_t>();
        TORCH_CHECK(ptr[0] == 0, "cu_seqlens must start at 0");
        TORCH_CHECK(ptr[meta.sequences] == meta.t,
                    "cu_seqlens must end at the packed token count");
        int64_t chunks = 0;
        for(int64_t i = 0; i < meta.sequences; ++i)
        {
            const int64_t length = ptr[i + 1] - ptr[i];
            TORCH_CHECK(length > 0, "sequence lengths must be positive");
            chunks += (length + kChunkSizeCk - 1) / kChunkSizeCk;
        }
        // A single logical sequence behaves exactly like the fixed-length path.
        meta.varlen     = meta.sequences > 1;
        meta.num_chunks = meta.varlen ? chunks : (meta.t + kChunkSizeCk - 1) / kChunkSizeCk;
    }
    else
    {
        meta.sequences  = 1;
        meta.varlen     = false;
        meta.num_chunks = (meta.t + kChunkSizeCk - 1) / kChunkSizeCk;
    }
    TORCH_CHECK(meta.t > 0 && meta.num_chunks > 0, "CK GDN requires a non-empty input");
    return meta;
}

PrefillShape make_shape(const Meta& meta)
{
    PrefillShape shape;
    shape.t          = meta.t;
    shape.h_qk       = meta.h_qk;
    shape.h_v        = meta.h_v;
    shape.sequences  = meta.sequences;
    shape.num_chunks = meta.num_chunks;
    shape.varlen     = meta.varlen;
    shape.is_bf16    = meta.is_bf16;
    return shape;
}

// Mirrors the state_cp_eligible decision in gdn_prefill.cpp so the adapter and
// the example pick the same state kernel.
int64_t state_cp_groups(const Meta& meta, const PrefillFlags& flags)
{
    const bool eligible = meta.is_bf16 && !flags.cp_context && !meta.varlen &&
                          meta.sequences == 1 && meta.t >= 1024 && meta.t % kChunkSizeCk == 0 &&
                          meta.h_v <= 16 && flags.use_g && !flags.use_gk && flags.use_exp2 &&
                          !flags.transpose_state;
    return eligible ? gdn_example::select_state_cp_groups(static_cast<int>(meta.t),
                                                          static_cast<int>(meta.h_v))
                    : 0;
}

float resolve_scale(const std::optional<double>& scale)
{
    if(!scale.has_value() || *scale == 0.0)
        return static_cast<float>(1.0 / std::sqrt(static_cast<double>(kHeadDimCk)));
    return static_cast<float>(*scale);
}

} // namespace

int64_t prefill_workspace_bytes_entry(const torch::Tensor& q,
                                      const torch::Tensor& v,
                                      const std::optional<torch::Tensor>& cu_seqlens,
                                      bool use_g,
                                      bool use_gk,
                                      bool use_exp2,
                                      bool transpose_state,
                                      bool qk_l2norm,
                                      bool gate_in_kernel,
                                      bool has_dt_bias,
                                      bool beta_sigmoid_in_kernel,
                                      bool output_final_state,
                                      bool cp_context,
                                      int64_t cp_world_size)
{
    const Meta meta = derive_meta(q, v, cu_seqlens);

    PrefillFlags flags;
    flags.use_g                  = use_g;
    flags.use_gk                 = use_gk;
    flags.use_exp2               = use_exp2;
    flags.transpose_state        = transpose_state;
    flags.qk_l2norm              = qk_l2norm;
    flags.gate_in_kernel         = gate_in_kernel;
    flags.has_dt_bias            = has_dt_bias;
    flags.beta_sigmoid_in_kernel = beta_sigmoid_in_kernel;
    flags.output_final_state     = output_final_state;
    flags.cp_context             = cp_context;
    flags.cp_world_size          = cp_world_size;

    auto shape           = make_shape(meta);
    flags.state_cp_groups = state_cp_groups(meta, flags);
    return prefill_workspace_bytes(shape, flags);
}

std::vector<torch::Tensor> prefill(const torch::Tensor& q,
                                   const torch::Tensor& k,
                                   const torch::Tensor& v,
                                   const std::optional<torch::Tensor>& g,
                                   const torch::Tensor& beta,
                                   const std::optional<torch::Tensor>& workspace,
                                   const std::optional<torch::Tensor>& gk,
                                   const std::optional<torch::Tensor>& a_log,
                                   const std::optional<torch::Tensor>& dt_bias,
                                   const std::optional<torch::Tensor>& initial_state,
                                   const std::optional<torch::Tensor>& cu_seqlens,
                                   const std::optional<double>& scale,
                                   bool use_g,
                                   bool use_gk,
                                   bool use_exp2,
                                   bool transpose_state,
                                   bool qk_l2norm,
                                   bool gate_in_kernel,
                                   bool has_dt_bias,
                                   bool beta_sigmoid_in_kernel,
                                   bool output_final_state,
                                   bool cp_context,
                                   int64_t cp_world_size,
                                   int64_t cp_rank)
{
    const Meta meta = derive_meta(q, v, cu_seqlens);
    check_packed_half(k, "k");
    TORCH_CHECK(k.size(0) == meta.t && k.size(1) == meta.h_qk &&
                    k.scalar_type() == q.scalar_type(),
                "k must be [tokens, h_qk, 128] with the same dtype as q");

    check_optional_f32(g, "g");
    check_optional_f32(gk, "gk");
    check_optional_f32(a_log, "a_log");
    check_optional_f32(dt_bias, "dt_bias");
    TORCH_CHECK(beta.is_cuda() && beta.is_contiguous() && beta.scalar_type() == at::kFloat,
                "beta must be a contiguous float32 device tensor");
    TORCH_CHECK(beta.numel() == meta.t * meta.h_v, "beta must have t * h_v elements");
    if(initial_state.has_value())
    {
        const auto& state = *initial_state;
        TORCH_CHECK(state.is_cuda() && state.is_contiguous() &&
                        state.scalar_type() == at::kFloat,
                    "initial_state must be a contiguous float32 device tensor");
        TORCH_CHECK(state.numel() == meta.sequences * meta.h_v * kHeadDimCk * kHeadDimCk,
                    "initial_state must be [sequences, h_v, 128, 128]");
    }

    TORCH_CHECK(!use_g || g.has_value(), "g is required when use_g is enabled");
    TORCH_CHECK(!use_gk || gk.has_value(), "gk is required when use_gk is enabled");
    TORCH_CHECK(!gate_in_kernel || a_log.has_value(),
                "a_log is required when gate_in_kernel is enabled");
    TORCH_CHECK(!has_dt_bias || gate_in_kernel,
                "has_dt_bias is only meaningful together with gate_in_kernel");
    if(cp_context)
    {
        TORCH_CHECK(cp_world_size >= 1 && cp_world_size <= 8,
                    "cp_world_size must be in [1,8] on the cp_context path");
        TORCH_CHECK(cp_rank >= 0 && cp_rank < cp_world_size,
                    "cp_rank must be in [0, cp_world_size)");
    }

    PrefillFlags flags;
    flags.use_g                  = use_g;
    flags.use_gk                 = use_gk;
    flags.use_exp2               = use_exp2;
    flags.transpose_state        = transpose_state;
    flags.qk_l2norm              = qk_l2norm;
    flags.gate_in_kernel         = gate_in_kernel;
    flags.has_dt_bias            = has_dt_bias;
    flags.beta_sigmoid_in_kernel = beta_sigmoid_in_kernel;
    flags.output_final_state     = output_final_state;
    flags.cp_context             = cp_context;
    flags.cp_world_size          = cp_world_size;
    flags.has_initial_state      = initial_state.has_value();

    auto shape            = make_shape(meta);
    flags.state_cp_groups = state_cp_groups(meta, flags);

    const int64_t needed = prefill_workspace_bytes(shape, flags);

    // An explicit workspace is the supported fast path (callers can cache and
    // reuse it). When it is omitted the adapter allocates one from the very
    // same shape/flags, so the size can never disagree with the launch.
    torch::Tensor workspace_tensor;
    if(workspace.has_value())
    {
        TORCH_CHECK(workspace->is_cuda() && workspace->is_contiguous() &&
                        workspace->scalar_type() == at::kByte,
                    "workspace must be a contiguous uint8 device tensor");
        TORCH_CHECK(workspace->numel() >= needed,
                    "workspace is too small: need ", needed, " bytes, got ",
                    workspace->numel(),
                    ". Use aiter_ck_gdn_prefill_workspace_bytes() with the same "
                    "flags to size it, or pass workspace=None to allocate "
                    "internally.");
        workspace_tensor = *workspace;
    }
    else
    {
        workspace_tensor = torch::empty({needed}, q.options().dtype(at::kByte));
    }

    const auto offsets = prefill_buffer_offsets(shape, flags);
    PrefillWorkspace ws(workspace_tensor.data_ptr<uint8_t>(), offsets);

    auto output = torch::empty({meta.t, meta.h_v, kHeadDimCk}, q.options());
    auto final_state = output_final_state
                           ? torch::empty({meta.sequences, meta.h_v, kHeadDimCk, kHeadDimCk},
                                          q.options().dtype(at::kFloat))
                           : torch::Tensor();

    // Optional inputs are turned into neutral pointers the same way the example
    // does: a small dummy buffer keeps every pointer valid.
    float* dummy = ws.at<float>(PfBuf::Dummy);

    const void* g_ptr    = use_g && g.has_value() ? g->data_ptr() : dummy;
    const void* gk_ptr   = use_gk && gk.has_value() ? gk->data_ptr() : dummy;
    const void* a_log_ptr = a_log.has_value() ? a_log->data_ptr() : dummy;
    const void* dt_bias_ptr = has_dt_bias && dt_bias.has_value() ? dt_bias->data_ptr() : nullptr;
    const void* beta_ptr = beta.data_ptr();
    const void* init_ptr = nullptr;
    if(cp_context)
        init_ptr = ws.at<float>(PfBuf::CpState);
    else if(initial_state.has_value())
        init_ptr = initial_state->data_ptr();

    const void* q_input = q.data_ptr();
    const void* k_input = k.data_ptr();
    const void* q_selected = qk_l2norm ? ws.at<void>(PfBuf::QNorm) : q_input;
    const void* k_selected = qk_l2norm ? ws.at<void>(PfBuf::KNorm) : k_input;

    gdn_example::PrefillArguments args{};
    args.q             = q_selected;
    args.k             = k_selected;
    args.v             = v.data_ptr();
    args.q_input       = q_input;
    args.k_input       = k_input;
    args.q_norm        = ws.at<void>(PfBuf::QNorm);
    args.k_norm        = ws.at<void>(PfBuf::KNorm);
    args.q_rstd        = ws.at<float>(PfBuf::QRstd);
    args.k_rstd        = ws.at<float>(PfBuf::KRstd);
    args.g             = static_cast<const float*>(g_ptr);
    args.gk            = static_cast<const float*>(gk_ptr);
    args.a_log         = static_cast<const float*>(a_log_ptr);
    args.dt_bias       = static_cast<const float*>(dt_bias_ptr);
    args.beta          = beta_sigmoid_in_kernel
                             ? static_cast<const float*>(ws.at<void>(PfBuf::BetaProcessed))
                             : static_cast<const float*>(beta_ptr);
    args.beta_input    = static_cast<const float*>(beta_ptr);
    args.beta_processed = ws.at<float>(PfBuf::BetaProcessed);
    args.initial_state = static_cast<const float*>(init_ptr);
    args.cu_seqlens    = cu_seqlens.has_value() ? cu_seqlens->data_ptr<int64_t>() : nullptr;
    args.chunk_offsets = ws.at<int64_t>(PfBuf::ChunkOffsets);
    args.chunk_indices = ws.at<int64_t>(PfBuf::ChunkIndices);
    args.g_cum         = ws.at<float>(PfBuf::Gcum);
    args.a             = reinterpret_cast<uint16_t*>(ws.at<void>(PfBuf::A));
    args.w             = reinterpret_cast<uint16_t*>(ws.at<void>(PfBuf::W));
    args.u             = reinterpret_cast<uint16_t*>(ws.at<void>(PfBuf::U));
    args.h             = reinterpret_cast<uint16_t*>(ws.at<void>(PfBuf::H));
    args.v_new         = reinterpret_cast<uint16_t*>(ws.at<void>(PfBuf::VNew));
    args.final_state   = output_final_state ? final_state.data_ptr<float>() : nullptr;
    args.state_input_workspace = ws.at<float>(PfBuf::StateInputWs);
    args.state_final_workspace = ws.at<float>(PfBuf::StateFinalWs);
    args.state_cp_group_a      = reinterpret_cast<uint16_t*>(ws.at<void>(PfBuf::CpGroupA));
    args.state_cp_group_b      = reinterpret_cast<uint16_t*>(ws.at<void>(PfBuf::CpGroupB));
    args.state_cp_group_start  = ws.at<float>(PfBuf::CpGroupStart);
    args.state_cp_groups       = static_cast<int>(flags.state_cp_groups);
    args.output = reinterpret_cast<uint16_t*>(output.data_ptr());
    args.cp_hm       = ws.at<float>(PfBuf::CpSummary);
    args.cp_ag_hm    = ws.at<float>(PfBuf::CpAgSummary);
    args.cp_state    = ws.at<float>(PfBuf::CpState);
    args.cp_world_size = static_cast<int>(cp_world_size);
    args.cp_rank       = static_cast<int>(cp_rank);
    args.t             = static_cast<int>(meta.t);
    args.h_qk          = static_cast<int>(meta.h_qk);
    args.h_v           = static_cast<int>(meta.h_v);
    args.head_dim      = static_cast<int>(kHeadDimCk);
    args.num_sequences = static_cast<int>(meta.sequences);
    args.num_chunks    = static_cast<int>(meta.num_chunks);
    args.scale         = resolve_scale(scale);
    args.output_final_state = output_final_state;
    args.is_varlen     = meta.varlen;
    args.use_qk_l2norm = qk_l2norm;
    args.cp_context    = cp_context;
    args.is_bf16       = meta.is_bf16;
    args.state_has_initial_state = cp_context || initial_state.has_value();
    args.state_store_final_state = output_final_state;
    // CK's output stage consumes v_new, so it is always materialised.
    args.state_save_new_value = true;
    args.state_use_g          = use_g;
    args.state_use_gk         = use_gk;
    args.state_use_exp2       = use_exp2;
    args.state_transpose_state = transpose_state;
    args.state_is_varlen      = meta.varlen;
    args.gate_in_kernel       = gate_in_kernel;
    args.has_dt_bias          = has_dt_bias;
    args.beta_sigmoid_in_kernel = beta_sigmoid_in_kernel;

    const hipStream_t stream = at::hip::getCurrentHIPStream();
    if(meta.is_bf16)
        gdn_example::launch_prefill_bf16(args, stream);
    else
        gdn_example::launch_prefill_fp16(args, stream);

    return {output, final_state};
}

} // namespace ck_gdn
} // namespace aiter
