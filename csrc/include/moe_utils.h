// SPDX-License-Identifier: MIT
// Copyright (C) 2024-2026, Advanced Micro Devices, Inc. All rights reserved.
//
// Modified by Hygon in 2026: extract MoE declarations and integrate AITER interfaces.

#pragma once
#include <torch/all.h>
#include <torch/extension.h>
#include "aiter_enum.h"
namespace aiter{
void topk_softmax(torch::Tensor &topk_weights, torch::Tensor &topk_indices,
                  torch::Tensor &token_expert_indices,
                  torch::Tensor &gating_output,
                  bool need_renorm);
void moe_sum(torch::Tensor &input, torch::Tensor &output);

                  
}

void biased_grouped_topk(torch::Tensor& gating_output,   // [num_tokens, num_experts]
                         torch::Tensor& correction_bias, // [num_expert]
                         torch::Tensor& topk_weights,    // [num_tokens, topk]
                         torch::Tensor& topk_ids,        // [num_tokens, topk]
                         int num_expert_group,
                         int topk_group,
                         bool renormalize,
                         const float routed_scaling_factor = 1.);

void grouped_topk(torch::Tensor& gating_output, // [num_tokens, num_experts]
                  torch::Tensor& topk_weights,  // [num_tokens, topk]
                  torch::Tensor& topk_ids,      // [num_tokens, topk]
                  int num_expert_group,
                  int topk_grp,
                  bool need_renorm,
                  bool is_softmax                   = true,
                  const float routed_scaling_factor = 1.);

std::vector<at::Tensor> moe_fused_gate(at::Tensor& input,
                                       at::Tensor& bias,
                                       at::Tensor& topk_weights,
                                       at::Tensor& topk_ids,
                                       int64_t num_expert_group,
                                       int64_t topk_group,
                                       int64_t topk,
                                       int64_t n_share_experts_fusion,
                                       double routed_scaling_factor);

void moe_align_block_size(torch::Tensor topk_ids, int64_t num_experts,
                          int64_t block_size, torch::Tensor sorted_token_ids,
                          torch::Tensor experts_ids,
                          torch::Tensor num_tokens_post_pad);

void sgl_moe_align_block_size(torch::Tensor topk_ids, int64_t num_experts,
                              int64_t block_size,
                              torch::Tensor sorted_token_ids,
                              torch::Tensor experts_ids,
                              torch::Tensor num_tokens_post_pad);

namespace aiter {

void ep_scatter(torch::Tensor aq,                      // [M, H] int8
                torch::Tensor aq_scale,                // [M] or [M, 1] fp32
                torch::Tensor topk_ids,                // [M, K] int64
                std::optional<torch::Tensor> expert_map, // int32, -1 = dropped
                torch::Tensor expert_num_tokens,       // [E] int32 counts (in) / offsets (out)
                torch::Tensor aq_out,                  // [M_sum, H] int8
                torch::Tensor aq_scale_out,            // [M_sum, 1] fp32
                torch::Tensor m_indices,               // [M_sum] int32
                torch::Tensor inv_perm,                // [M, K] int32
                int local_num_experts, int alignment);

void ep_gather(torch::Tensor a,                        // [M_sum, H] fp16/bf16/fp32
               torch::Tensor topk_ids,                 // [M, K] int64
               torch::Tensor topk_weights,             // [M, K] fp32
               torch::Tensor inv_perm,                 // [M, K] int32
               std::optional<torch::Tensor> expert_map, // int32
               torch::Tensor output);                  // [M, H]

void ep_build_m_indices(torch::Tensor topk_ids,        // [M, K] int32/int64
                        torch::Tensor m_indices,       // [M_sum] int32
                        int local_num_experts, int alignment);

void ep_fused_quant_scatter(torch::Tensor input,       // [M, H] fp16/bf16
                            torch::Tensor topk_ids,    // [M, K] int64
                            std::optional<torch::Tensor> expert_map,
                            torch::Tensor expert_num_tokens,
                            torch::Tensor aq_out,      // [M_sum, H] int8
                            torch::Tensor aq_scale_out, // [M_sum, 1] fp32
                            torch::Tensor m_indices, torch::Tensor inv_perm,
                            int local_num_experts, int alignment);

void ep_fused_fp8_quant_scatter(torch::Tensor input,   // [M, H] fp16/bf16
                                torch::Tensor topk_ids,
                                std::optional<torch::Tensor> expert_map,
                                torch::Tensor expert_num_tokens,
                                torch::Tensor aq_out,  // [M_sum, H] fp8 bytes
                                torch::Tensor aq_scale_out,
                                torch::Tensor m_indices, torch::Tensor inv_perm,
                                int local_num_experts, int alignment,
                                int fp8type /*0=e4m3,1=e5m2*/,
                                bool fill_padded_m_indices);

void ep_fused_smooth_quant_scatter(torch::Tensor input, // [M, H] fp16/bf16
                                   torch::Tensor topk_ids,
                                   std::optional<torch::Tensor> expert_map,
                                   torch::Tensor expert_offsets, // [E] int32 start offsets
                                   torch::Tensor smooth_scale,  // [E, H] fp32
                                   torch::Tensor aq_out, torch::Tensor aq_scale_out,
                                   torch::Tensor m_indices, torch::Tensor inv_perm,
                                   int local_num_experts, int alignment);

} // namespace aiter

