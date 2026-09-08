// SPDX-License-Identifier: MIT

#pragma once

#include <torch/torch.h>

#include <vector>

#include "aiter_common.h"

namespace aiter {
namespace native {

AITER_CPP_TORCH_API void topk_softmax(torch::Tensor& topk_weights,
                                      torch::Tensor& topk_indices,
                                      torch::Tensor& token_expert_indices,
                                      torch::Tensor& gating_output,
                                      bool need_renorm);

AITER_CPP_TORCH_API void grouped_topk(torch::Tensor& gating_output,
                                      torch::Tensor& topk_weights,
                                      torch::Tensor& topk_ids,
                                      int num_expert_group,
                                      int topk_group,
                                      bool need_renorm,
                                      bool is_softmax = true,
                                      float routed_scaling_factor = 1.0f);

AITER_CPP_TORCH_API void biased_grouped_topk(torch::Tensor& gating_output,
                                             torch::Tensor& correction_bias,
                                             torch::Tensor& topk_weights,
                                             torch::Tensor& topk_ids,
                                             int num_expert_group,
                                             int topk_group,
                                             bool need_renorm,
                                             float routed_scaling_factor = 1.0f);

AITER_CPP_TORCH_API std::vector<at::Tensor>
moe_fused_gate(at::Tensor& input,
               at::Tensor& bias,
               at::Tensor& topk_weights,
               at::Tensor& topk_ids,
               int64_t num_expert_group,
               int64_t topk_group,
               int64_t topk,
               int64_t num_fused_shared_experts,
               double routed_scaling_factor);

} // namespace native
} // namespace aiter
