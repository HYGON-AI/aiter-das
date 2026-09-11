// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#include "moe_sorting.h"

#include <ATen/ATen.h>
#include <hip/hip_runtime.h>
#include <torch/torch.h>

#include <iostream>
#include <optional>
#include <stdexcept>
#include <tuple>

namespace {

constexpr int kBlockSize = 32;

struct Expected
{
    torch::Tensor sorted_ids;
    torch::Tensor sorted_weights;
    torch::Tensor sorted_expert_ids;
    torch::Tensor num_valid_ids;
    torch::Tensor positions;
};

Expected reference_moe_sorting(const torch::Tensor& topk_ids,
                               const torch::Tensor& topk_weights,
                               int num_experts,
                               const std::optional<torch::Tensor>& expert_mask)
{
    const auto device = topk_ids.device();
    const int64_t tokens = topk_ids.size(0);
    const int64_t topk = topk_ids.size(1);
    const int64_t max_num_tokens_padded =
        topk_ids.numel() + num_experts * kBlockSize - topk;
    const int64_t max_num_m_blocks =
        (max_num_tokens_padded + kBlockSize - 1) / kBlockSize;
    const int32_t init_val = static_cast<int32_t>((topk << 24) | tokens);

    auto int_opts = torch::TensorOptions().dtype(torch::kInt32).device(device);
    auto fp_opts = torch::TensorOptions().dtype(torch::kFloat32).device(device);
    auto sorted_ids = torch::full({max_num_tokens_padded}, init_val, int_opts);
    auto sorted_weights = torch::zeros({max_num_tokens_padded}, fp_opts);
    auto sorted_expert_ids = torch::full({max_num_m_blocks}, -1, int_opts);
    auto num_valid_ids = torch::empty({1}, int_opts);
    auto positions = torch::zeros({num_experts * 2}, int_opts);

    int64_t sorted_ids_begin = 0;
    int64_t sorted_expert_ids_begin = 0;
    int skip_expert_num = 0;
    for(int expert_id = 0; expert_id < num_experts; ++expert_id)
    {
        positions[num_experts + expert_id] = sorted_ids_begin;
        if(expert_mask.has_value() && expert_mask.value()[expert_id].item<int32_t>() == 0)
        {
            ++skip_expert_num;
            continue;
        }
        auto where = torch::where(topk_ids == expert_id);
        auto token_id = where[0];
        auto topk_id = where[1];
        const int64_t tokens_num = token_id.numel();
        positions[expert_id] = tokens_num;
        const int64_t expert_blocks = (tokens_num + kBlockSize - 1) / kBlockSize;
        sorted_ids.slice(0, sorted_ids_begin, sorted_ids_begin + tokens_num)
            .copy_(topk_id * (1 << 24) + token_id);
        sorted_weights.slice(0, sorted_ids_begin, sorted_ids_begin + tokens_num)
            .copy_(topk_weights.index({token_id, topk_id}));
        sorted_expert_ids
            .slice(0, sorted_expert_ids_begin, sorted_expert_ids_begin + expert_blocks)
            .fill_(expert_id - skip_expert_num);
        sorted_ids_begin += expert_blocks * kBlockSize;
        sorted_expert_ids_begin += expert_blocks;
    }

    num_valid_ids[0] = sorted_ids_begin;
    return {sorted_ids, sorted_weights, sorted_expert_ids, num_valid_ids, positions};
}

void require(bool ok, const char* msg)
{
    if(!ok)
    {
        throw std::runtime_error(msg);
    }
}

void run_case(int tokens, int topk, int num_experts, bool with_mask, bool with_moe_buf,
              int invalid_mode = 0)
{
    torch::manual_seed(tokens * 1000 + topk * 10 + num_experts);
    auto int_opts = torch::TensorOptions().dtype(torch::kInt32).device(torch::kCUDA);
    auto fp_opts = torch::TensorOptions().dtype(torch::kFloat32).device(torch::kCUDA);
    auto bf16_opts = torch::TensorOptions().dtype(torch::kBFloat16).device(torch::kCUDA);

    auto scores = torch::rand({tokens, num_experts}, fp_opts);
    auto topk_ret = torch::topk(scores, topk, 1);
    auto topk_weights = std::get<0>(topk_ret);
    auto topk_ids = std::get<1>(topk_ret).to(torch::kInt32);
    if(invalid_mode == 1)
        topk_ids.fill_(-1);
    else if(invalid_mode == 2)
    {
        topk_ids.select(1, 0).fill_(-1);
        topk_ids.select(1, 1).fill_(num_experts);
    }

    std::optional<torch::Tensor> expert_mask = std::nullopt;
    if(with_mask)
    {
        auto mask = torch::randint(0, 2, {num_experts}, int_opts);
        mask[0] = 1;
        expert_mask = mask;
    }

    const int64_t max_num_tokens_padded =
        topk_ids.numel() + num_experts * kBlockSize - topk;
    const int64_t max_num_m_blocks =
        (max_num_tokens_padded + kBlockSize - 1) / kBlockSize;

    auto sorted_ids = torch::empty({max_num_tokens_padded}, int_opts);
    auto sorted_weights = torch::empty({max_num_tokens_padded}, fp_opts);
    auto sorted_expert_ids = torch::empty({max_num_m_blocks}, int_opts);
    auto tokens_positions_per_expert = torch::full({num_experts * 2}, -777, int_opts);
    auto num_valid_ids = torch::empty({1}, int_opts);
    std::optional<torch::Tensor> moe_buf = std::nullopt;
    if(with_moe_buf)
    {
        moe_buf = torch::full({tokens, 64}, 13, bf16_opts);
    }

    aiter::native::moe_sorting_fwd(topk_ids,
                                   topk_weights,
                                   sorted_ids,
                                   sorted_weights,
                                   sorted_expert_ids,
                                   tokens_positions_per_expert,
                                   num_valid_ids,
                                   moe_buf,
                                   num_experts,
                                   kBlockSize,
                                   expert_mask);

    auto expected = reference_moe_sorting(topk_ids, topk_weights, num_experts, expert_mask);
    (void)hipDeviceSynchronize();

    const int64_t valid_count = expected.num_valid_ids.item<int32_t>();
    auto valid_expert_mask = expected.sorted_expert_ids != -1;

    require(torch::equal(num_valid_ids, expected.num_valid_ids), "num_valid_ids mismatch");
    require(torch::equal(sorted_ids.slice(0, 0, valid_count),
                         expected.sorted_ids.slice(0, 0, valid_count)),
            "sorted_ids mismatch");
    require(torch::equal(sorted_weights.slice(0, 0, valid_count),
                         expected.sorted_weights.slice(0, 0, valid_count)),
            "sorted_weights mismatch");
    require(torch::equal(tokens_positions_per_expert, expected.positions),
            "expert metadata mismatch");
    if(moe_buf.has_value())
        require(torch::count_nonzero(*moe_buf).item<int64_t>() == 0, "moe_buf was not cleared");
    require(torch::equal(sorted_expert_ids.index({valid_expert_mask}),
                         expected.sorted_expert_ids.index({valid_expert_mask})),
            "sorted_expert_ids mismatch");

    std::cout << "case passed: tokens=" << tokens << " topk=" << topk
              << " experts=" << num_experts << " mask=" << with_mask
              << " moe_buf=" << with_moe_buf << " invalid=" << invalid_mode << "\n";
}

} // namespace

int main()
{
    if(!torch::cuda::is_available())
    {
        std::cerr << "CUDA/HIP device is not available\n";
        return 1;
    }

    run_case(7, 5, 5, false, true);
    run_case(64, 5, 32, true, true);
    run_case(257, 8, 96, true, false);
    run_case(7, 5, 5, false, true, 1);
    run_case(7, 5, 5, true, false, 2);
    run_case(8192, 10, 512, false, true, 1);
    run_case(8192, 10, 512, true, false, 2);
    std::cout << "all libtorch moe_sorting tests passed\n";
    return 0;
}
