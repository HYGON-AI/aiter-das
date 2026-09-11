// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#include "aiter_c_ops.h"

#include <hip/hip_runtime.h>
#include <torch/torch.h>

#include <cmath>
#include <iostream>
#include <stdexcept>
#include <string>
#include <tuple>
#include <vector>

namespace {

struct DTypeCase
{
    const char* name;
    at::ScalarType dtype;
    double rtol;
    double atol;
};

const std::vector<DTypeCase> kDTypes = {
    {"fp32", at::kFloat, 1e-4, 1e-5},
    {"fp16", at::kHalf, 2e-2, 2e-3},
    {"bf16", at::kBFloat16, 3e-2, 3e-3},
};

void require(bool ok, const std::string& message)
{
    if(!ok)
    {
        throw std::runtime_error(message);
    }
}

torch::Tensor make_logits(int64_t tokens, int64_t experts, at::ScalarType dtype)
{
    auto opts = torch::TensorOptions().device(torch::kCUDA).dtype(torch::kFloat);
    return (torch::randn({tokens, experts}, opts) / 3.0).to(dtype).contiguous();
}

torch::Tensor make_bias(int64_t experts, at::ScalarType dtype)
{
    auto opts = torch::TensorOptions().device(torch::kCUDA).dtype(torch::kFloat);
    return (torch::randn({experts}, opts) / 8.0).to(dtype).contiguous();
}

std::tuple<torch::Tensor, torch::Tensor>
reference_topk_softmax(const torch::Tensor& gating_output, int64_t topk, bool need_renorm)
{
    auto scores = torch::softmax(gating_output.to(torch::kFloat), -1);
    auto topk_result = torch::topk(scores, topk, -1, true, false);
    auto weights = std::get<0>(topk_result);
    auto ids = std::get<1>(topk_result).to(torch::kInt32);
    if(need_renorm)
    {
        weights = weights / weights.sum(-1, true);
    }
    return {weights.contiguous(), ids.contiguous()};
}

torch::Tensor reference_token_expert_indices(int64_t tokens, int64_t topk)
{
    auto opts = torch::TensorOptions().device(torch::kCUDA).dtype(torch::kInt32);
    auto token_ids = torch::arange(tokens, opts).view({tokens, 1});
    auto topk_offsets = torch::arange(topk, opts).view({1, topk}) * tokens;
    return (token_ids + topk_offsets).contiguous();
}

std::tuple<torch::Tensor, torch::Tensor>
reference_grouped_topk(const torch::Tensor& gating_output,
                       int64_t topk,
                       int64_t num_expert_group,
                       int64_t topk_group,
                       bool need_renorm,
                       bool is_softmax,
                       double routed_scaling_factor)
{
    auto scores = is_softmax ? torch::softmax(gating_output.to(torch::kFloat), -1)
                             : torch::sigmoid(gating_output.to(torch::kFloat));
    const int64_t tokens = scores.size(0);
    const int64_t experts = scores.size(1);
    const int64_t experts_per_group = experts / num_expert_group;

    auto group_scores =
        std::get<0>(scores.view({tokens, num_expert_group, experts_per_group}).max(-1));
    auto group_idx = std::get<1>(torch::topk(group_scores, topk_group, -1, true, false));
    auto group_mask = torch::zeros(group_scores.sizes(),
                                   group_scores.options().dtype(torch::kFloat));
    group_mask.scatter_(1, group_idx, 1.0);
    auto score_mask = group_mask.unsqueeze(-1)
                          .expand({tokens, num_expert_group, experts_per_group})
                          .reshape({tokens, experts})
                          .to(torch::kBool);
    auto tmp_scores = scores.masked_fill(score_mask.logical_not(), -INFINITY);
    auto topk_result = torch::topk(tmp_scores, topk, -1, true, false);
    auto weights = std::get<0>(topk_result);
    auto ids = std::get<1>(topk_result).to(torch::kInt32);
    if(need_renorm)
    {
        weights = weights / weights.sum(-1, true);
    }
    weights = weights * routed_scaling_factor;
    return {weights.contiguous(), ids.contiguous()};
}

std::tuple<torch::Tensor, torch::Tensor>
reference_biased_grouped_topk(const torch::Tensor& gating_output,
                              const torch::Tensor& correction_bias,
                              int64_t topk,
                              int64_t num_expert_group,
                              int64_t topk_group,
                              bool need_renorm,
                              double routed_scaling_factor)
{
    auto scores = torch::sigmoid(gating_output.to(torch::kFloat));
    auto scores_for_choice = scores + correction_bias.to(torch::kFloat).unsqueeze(0);
    const int64_t tokens = scores.size(0);
    const int64_t experts = scores.size(1);
    const int64_t experts_per_group = experts / num_expert_group;

    auto group_scores =
        std::get<0>(scores_for_choice.view({tokens, num_expert_group, experts_per_group})
                        .topk(2, -1, true, false))
            .sum(-1);
    auto group_idx = std::get<1>(torch::topk(group_scores, topk_group, -1, true, false));
    auto group_mask = torch::zeros(group_scores.sizes(),
                                   group_scores.options().dtype(torch::kFloat));
    group_mask.scatter_(1, group_idx, 1.0);
    auto score_mask = group_mask.unsqueeze(-1)
                          .expand({tokens, num_expert_group, experts_per_group})
                          .reshape({tokens, experts})
                          .to(torch::kBool);
    auto tmp_scores = scores_for_choice.masked_fill(score_mask.logical_not(), -INFINITY);
    auto ids = std::get<1>(torch::topk(tmp_scores, topk, -1, true, false)).to(torch::kInt32);
    auto weights = scores.gather(1, ids.to(torch::kLong));
    if(need_renorm)
    {
        weights = weights / weights.sum(-1, true);
    }
    weights = weights * routed_scaling_factor;
    return {weights.contiguous(), ids.contiguous()};
}

std::tuple<torch::Tensor, torch::Tensor>
reference_moe_fused_gate(const torch::Tensor& gating_output,
                         const torch::Tensor& correction_bias,
                         int64_t topk,
                         int64_t num_expert_group,
                         int64_t topk_group,
                         int64_t num_fused_shared_experts,
                         double routed_scaling_factor)
{
    auto scores = torch::sigmoid(gating_output.to(torch::kFloat));
    auto scores_for_choice = scores + correction_bias.to(torch::kFloat).unsqueeze(0);
    const int64_t tokens = scores.size(0);
    const int64_t experts = scores.size(1);
    const int64_t routed_topk = topk - num_fused_shared_experts;
    const int64_t experts_per_group = experts / num_expert_group;

    auto group_scores =
        std::get<0>(scores_for_choice.view({tokens, num_expert_group, experts_per_group})
                        .topk(2, -1, true, false))
            .sum(-1);
    auto group_idx = std::get<1>(torch::topk(group_scores, topk_group, -1, true, false));
    auto group_mask = torch::zeros(group_scores.sizes(),
                                   group_scores.options().dtype(torch::kFloat));
    group_mask.scatter_(1, group_idx, 1.0);
    auto score_mask = group_mask.unsqueeze(-1)
                          .expand({tokens, num_expert_group, experts_per_group})
                          .reshape({tokens, experts})
                          .to(torch::kBool);
    auto tmp_scores = scores_for_choice.masked_fill(score_mask.logical_not(), -INFINITY);
    auto routed_ids =
        std::get<1>(torch::topk(tmp_scores, routed_topk, -1, true, false)).to(torch::kInt32);
    auto routed_weights = scores.gather(1, routed_ids.to(torch::kLong));

    torch::Tensor ids;
    torch::Tensor weights;
    if(num_fused_shared_experts > 0)
    {
        ids = torch::empty({tokens, topk},
                           torch::TensorOptions().device(torch::kCUDA).dtype(torch::kInt32));
        weights = torch::empty({tokens, topk},
                               torch::TensorOptions().device(torch::kCUDA).dtype(torch::kFloat));
        ids.slice(1, 0, routed_topk).copy_(routed_ids);
        weights.slice(1, 0, routed_topk).copy_(routed_weights);
        auto routed_sum = routed_weights.sum(-1, true);
        for(int64_t i = 0; i < num_fused_shared_experts; ++i)
        {
            ids.slice(1, routed_topk + i, routed_topk + i + 1).fill_(experts + i);
            weights.slice(1, routed_topk + i, routed_topk + i + 1)
                .copy_(routed_sum / routed_scaling_factor);
        }
    }
    else
    {
        ids = routed_ids;
        weights = routed_weights;
    }

    auto norm_sum = weights.slice(1, 0, routed_topk).sum(-1, true);
    weights = weights / norm_sum;
    return {weights.contiguous(), ids.contiguous()};
}

void check_topk(const std::string& name,
                const DTypeCase& dtype_case,
                const torch::Tensor& output_weights,
                const torch::Tensor& output_ids,
                const torch::Tensor& ref_weights,
                const torch::Tensor& ref_ids)
{
    auto out_sort = output_ids.sort(1);
    auto ref_sort = ref_ids.sort(1);
    auto out_ids = std::get<0>(out_sort);
    auto ref_ids_sorted = std::get<0>(ref_sort);
    require(torch::equal(out_ids, ref_ids_sorted), name + " ids mismatch");

    auto out_weights = output_weights.gather(1, std::get<1>(out_sort)).to(torch::kFloat);
    auto ref_weights_sorted = ref_weights.gather(1, std::get<1>(ref_sort)).to(torch::kFloat);
    if(!torch::allclose(out_weights, ref_weights_sorted, dtype_case.rtol, dtype_case.atol, true))
    {
        const double max_abs = (out_weights - ref_weights_sorted).abs().max().item<double>();
        throw std::runtime_error(name + " weights mismatch for " + dtype_case.name +
                                 ", max_abs=" + std::to_string(max_abs));
    }
}

void run_topk_softmax_case(const DTypeCase& dtype_case, bool need_renorm)
{
    constexpr int64_t tokens = 37;
    constexpr int64_t experts = 128;
    constexpr int64_t topk = 6;
    auto logits = make_logits(tokens, experts, dtype_case.dtype);
    auto weights = torch::empty({tokens, topk},
                                torch::TensorOptions().device(torch::kCUDA).dtype(torch::kFloat));
    auto ids = torch::empty({tokens, topk},
                            torch::TensorOptions().device(torch::kCUDA).dtype(torch::kInt32));
    auto token_expert_indices =
        torch::empty({tokens, topk},
                     torch::TensorOptions().device(torch::kCUDA).dtype(torch::kInt32));

    aiter::native::topk_softmax(weights, ids, token_expert_indices, logits, need_renorm);
    auto [ref_weights, ref_ids] = reference_topk_softmax(logits, topk, need_renorm);
    check_topk(std::string("topk_softmax renorm=") + (need_renorm ? "true" : "false"),
               dtype_case,
               weights,
               ids,
               ref_weights,
               ref_ids);

    require(torch::equal(token_expert_indices, reference_token_expert_indices(tokens, topk)),
            "topk_softmax token_expert_indices mismatch");
}

void run_grouped_topk_case(const DTypeCase& dtype_case, bool is_softmax)
{
    constexpr int64_t tokens = 41;
    constexpr int64_t experts = 256;
    constexpr int64_t groups = 8;
    constexpr int64_t topk_group = 4;
    constexpr int64_t topk = 8;
    constexpr bool need_renorm = true;
    constexpr float route_scale = 1.25f;
    auto logits = make_logits(tokens, experts, dtype_case.dtype);
    auto weights = torch::empty({tokens, topk},
                                torch::TensorOptions().device(torch::kCUDA).dtype(torch::kFloat));
    auto ids = torch::empty({tokens, topk},
                            torch::TensorOptions().device(torch::kCUDA).dtype(torch::kInt32));

    aiter::native::grouped_topk(
        logits, weights, ids, groups, topk_group, need_renorm, is_softmax, route_scale);
    auto [ref_weights, ref_ids] = reference_grouped_topk(
        logits, topk, groups, topk_group, need_renorm, is_softmax, route_scale);
    check_topk(std::string("grouped_topk softmax=") + (is_softmax ? "true" : "false"),
               dtype_case,
               weights,
               ids,
               ref_weights,
               ref_ids);
}

void run_biased_grouped_topk_case(const DTypeCase& dtype_case)
{
    constexpr int64_t tokens = 43;
    constexpr int64_t experts = 256;
    constexpr int64_t groups = 8;
    constexpr int64_t topk_group = 4;
    constexpr int64_t topk = 8;
    constexpr bool need_renorm = true;
    constexpr float route_scale = 1.5f;
    auto logits = make_logits(tokens, experts, dtype_case.dtype);
    auto bias = make_bias(experts, dtype_case.dtype);
    auto weights = torch::empty({tokens, topk},
                                torch::TensorOptions().device(torch::kCUDA).dtype(torch::kFloat));
    auto ids = torch::empty({tokens, topk},
                            torch::TensorOptions().device(torch::kCUDA).dtype(torch::kInt32));

    aiter::native::biased_grouped_topk(
        logits, bias, weights, ids, groups, topk_group, need_renorm, route_scale);
    auto [ref_weights, ref_ids] =
        reference_biased_grouped_topk(logits, bias, topk, groups, topk_group, need_renorm, route_scale);
    check_topk("biased_grouped_topk", dtype_case, weights, ids, ref_weights, ref_ids);
}

void run_moe_fused_gate_case(const DTypeCase& dtype_case, int64_t num_fused_shared_experts)
{
    constexpr int64_t tokens = 47;
    constexpr int64_t experts = 256;
    constexpr int64_t groups = 8;
    constexpr int64_t topk_group = 4;
    const int64_t routed_topk = 8;
    const int64_t topk = routed_topk + num_fused_shared_experts;
    constexpr double route_scale = 2.5;
    auto logits = make_logits(tokens, experts, dtype_case.dtype);
    auto bias = make_bias(experts, dtype_case.dtype);
    auto weights = torch::empty({tokens, topk},
                                torch::TensorOptions().device(torch::kCUDA).dtype(torch::kFloat));
    auto ids = torch::empty({tokens, topk},
                            torch::TensorOptions().device(torch::kCUDA).dtype(torch::kInt32));

    auto returned = aiter::native::moe_fused_gate(
        logits, bias, weights, ids, groups, topk_group, topk, num_fused_shared_experts, route_scale);
    require(returned.size() == 2, "moe_fused_gate return count mismatch");
    require(returned[0].data_ptr() == weights.data_ptr(), "moe_fused_gate weight return alias mismatch");
    require(returned[1].data_ptr() == ids.data_ptr(), "moe_fused_gate id return alias mismatch");

    auto [ref_weights, ref_ids] = reference_moe_fused_gate(
        logits, bias, topk, groups, topk_group, num_fused_shared_experts, route_scale);
    check_topk("moe_fused_gate", dtype_case, weights, ids, ref_weights, ref_ids);
}

} // namespace

int main()
{
    if(!torch::cuda::is_available())
    {
        std::cerr << "CUDA/HIP device is not available\n";
        return 1;
    }

    torch::manual_seed(20260625);
    for(const auto& dtype_case : kDTypes)
    {
        run_topk_softmax_case(dtype_case, false);
        run_topk_softmax_case(dtype_case, true);
        run_grouped_topk_case(dtype_case, true);
        run_grouped_topk_case(dtype_case, false);
        run_biased_grouped_topk_case(dtype_case);
        run_moe_fused_gate_case(dtype_case, 0);
        run_moe_fused_gate_case(dtype_case, 1);
        std::cout << "passed dtype=" << dtype_case.name << "\n";
    }
    require(hipDeviceSynchronize() == hipSuccess, "hipDeviceSynchronize failed");
    std::cout << "all libtorch topk/gate tests passed\n";
    return 0;
}
