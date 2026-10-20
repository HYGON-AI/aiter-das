// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
//
// CK GDN native adapter -- entry points.
//
// These mirror the CK GDN example launchers one-to-one:
//   prefill -> gdn_example::launch_prefill_{bf16,fp16}
//   decode  -> gdn_decode_example::launch_{bf16,fp16}
// The adapter only converts tensors, derives metadata, carves the caller
// provided workspace and picks the dtype entry; all scheduling stays inside CK.
//
// This header intentionally avoids CK includes so the pybind translation unit
// does not pull the CK submodule.
#pragma once

#include <torch/extension.h>

#include <cstdint>
#include <optional>
#include <vector>

namespace aiter {
namespace ck_gdn {

// Bytes the caller must allocate for aiter_ck_gdn_prefill's workspace tensor.
// Sized from the same tensors/flags as the launch entry, so the two can never
// disagree.
int64_t prefill_workspace_bytes_entry(
    const torch::Tensor& q,
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
    int64_t cp_world_size);

// CK GDN prefill pipeline (preprocess -> cumsum -> kkt -> recompute_w_u ->
// state -> output). Returns {output, final_state}; final_state is undefined
// when output_final_state is false.
//
// Tensors are packed, without a leading batch dimension:
//   q,k [t, h_qk, 128], v [t, h_v, 128], g/gk/beta [t, h_v] fp32,
//   initial_state [sequences, h_v, 128, 128] fp32, cu_seqlens [sequences+1] int64,
//   workspace a flat uint8 tensor of prefill_workspace_bytes_entry() bytes.
// Passing an undefined workspace allocates one freshly with the same flags.
std::vector<torch::Tensor> prefill(
    const torch::Tensor& q,
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
    int64_t cp_rank);

// CK GDN fused recurrent decode. Returns {output, final_state}; final_state is
// undefined when store_final_state is false.
//
// Tensors are packed as well: q,k [tokens, h_qk, 128], v [tokens, h_v, 128],
// g/gk/gv/beta [tokens, h_v], cu_seqlens [sequences+1] int64,
// initial_state [sequences, h_v, 128, 128] fp32.
//
// validate_varlen=false skips the host-side cu_seqlens checks, which are the
// only reason the entry needs the values on the host (and therefore a stream
// sync). It is a pure optimization: the kernel reads cu_seqlens on device, so
// results are unaffected. Keep the default when the values come from a caller
// that may not have validated them.
std::vector<torch::Tensor> decode(
    const torch::Tensor& q,
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
    bool store_final_state,
    bool validate_varlen = true);

} // namespace ck_gdn
} // namespace aiter
