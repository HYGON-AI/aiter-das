#pragma once

#include <torch/extension.h>

torch::Tensor moe_c_moe_gemm_marlin_wfp4a8_channelwise(torch::Tensor input,
                                                       torch::Tensor b_qweight,
                                                       torch::Tensor output,
                                                       torch::Tensor a_scale,
                                                       torch::Tensor b_scale,
                                                       std::optional<torch::Tensor> topk_weights,
                                                       torch::Tensor sorted_token_ids,
                                                       torch::Tensor expert_ids,
                                                       torch::Tensor num_tokens_post_pad,
                                                       int64_t top_k,
                                                       int64_t mode,
                                                       int64_t delta,
                                                       int64_t config_m);

torch::Tensor moe_c_moe_gemm_marlin_wfp4a8_groupwise(torch::Tensor input,
                                                     torch::Tensor b_qweight,
                                                     torch::Tensor output,
                                                     torch::Tensor a_scale,
                                                     torch::Tensor b_scale,
                                                     std::optional<torch::Tensor> topk_weights,
                                                     torch::Tensor sorted_token_ids,
                                                     torch::Tensor expert_ids,
                                                     torch::Tensor num_tokens_post_pad,
                                                     int64_t top_k,
                                                     int64_t mode,
                                                     int64_t delta,
                                                     int64_t config_m);

torch::Tensor moe_c_moe_gemm_marlin_wfp4a8_groupwise_qgroup(torch::Tensor input,
                                                            torch::Tensor b_qweight,
                                                            torch::Tensor output,
                                                            torch::Tensor a_scale,
                                                            torch::Tensor b_scale,
                                                            std::optional<torch::Tensor> topk_weights,
                                                            torch::Tensor sorted_token_ids,
                                                            torch::Tensor expert_ids,
                                                            torch::Tensor num_tokens_post_pad,
                                                            int64_t top_k,
                                                            int64_t mode,
                                                            int64_t delta,
                                                            int64_t config_m);
