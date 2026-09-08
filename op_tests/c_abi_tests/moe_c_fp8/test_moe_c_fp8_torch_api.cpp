// SPDX-License-Identifier: MIT

#include "aiter_c_ops.h"

#include <ATen/ATen.h>
#include <hip/hip_runtime.h>
#include <torch/torch.h>

#include <iostream>
#include <optional>
#include <stdexcept>
#include <vector>

namespace {

constexpr int64_t kTokens = 1;
constexpr int64_t kExperts = 256;
constexpr int64_t kTopK = 8;
constexpr int64_t kHidden = 7168;
constexpr int64_t kInterDim = 128;
constexpr int64_t kOutChannels = 2 * kInterDim;
constexpr int64_t kBlockM = 16;
constexpr int64_t kMode = 60121;
constexpr int64_t kKeySelected = 1;

void require(bool ok, const std::string& message)
{
    if(!ok)
    {
        throw std::runtime_error(message);
    }
}

torch::Tensor moe_layout_shuffle_gemm2(const torch::Tensor& weight_input)
{
    auto weight = weight_input.permute({0, 2, 1}).contiguous();
    const int64_t experts = weight.size(0);
    const int64_t size_k = weight.size(1);
    const int64_t size_n = weight.size(2);

    auto shuffled = weight.reshape({experts, size_k / 64, 64, size_n / 16, 16});
    shuffled = shuffled.permute({0, 1, 3, 4, 2}).contiguous();
    shuffled = shuffled.reshape({experts, size_k / 64, size_n / 16, 1, 16, 4, 16});
    shuffled = shuffled.permute({0, 1, 2, 3, 5, 4, 6}).contiguous();
    return shuffled.view(weight_input.sizes());
}

struct SortedTokens
{
    torch::Tensor sorted_token_ids;
    torch::Tensor sorted_weights;
    torch::Tensor expert_ids;
    torch::Tensor tokens_positions_per_expert;
    torch::Tensor num_tokens_post_pad;
};

SortedTokens make_sorted_tokens(torch::Tensor topk_ids,
                                torch::Tensor topk_weights)
{
    auto int_opts = torch::TensorOptions().dtype(torch::kInt32).device(torch::kCUDA);
    auto fp_opts = torch::TensorOptions().dtype(torch::kFloat).device(torch::kCUDA);
    const int64_t max_num_tokens_padded =
        topk_ids.numel() + kExperts * kBlockM - kTopK;
    const int64_t max_num_m_blocks =
        (max_num_tokens_padded + kBlockM - 1) / kBlockM;

    SortedTokens sorted{
        torch::empty({max_num_tokens_padded}, int_opts),
        torch::empty({max_num_tokens_padded}, fp_opts),
        torch::empty({max_num_m_blocks}, int_opts),
        torch::empty({kExperts * 2}, int_opts),
        torch::empty({1}, int_opts)};

    aiter::native::moe_sorting_fwd(topk_ids,
                                   topk_weights,
                                   sorted.sorted_token_ids,
                                   sorted.sorted_weights,
                                   sorted.expert_ids,
                                   sorted.tokens_positions_per_expert,
                                   sorted.num_tokens_post_pad,
                                   std::nullopt,
                                   kExperts,
                                   kBlockM,
                                   std::nullopt);
    require(hipDeviceSynchronize() == hipSuccess, "moe_sorting_fwd synchronize failed");
    return sorted;
}

torch::Tensor make_reference(const torch::Tensor& raw_weight,
                             const torch::Tensor& weight_scale,
                             int64_t k_index)
{
    auto expected = torch::empty({kTokens, kTopK, kOutChannels},
                                 torch::TensorOptions()
                                     .device(torch::kCUDA)
                                     .dtype(torch::kBFloat16));
    for(int64_t topk_idx = 0; topk_idx < kTopK; ++topk_idx)
    {
        auto expert = topk_idx;
        auto ref = raw_weight.index({expert, torch::indexing::Slice(), k_index}).to(torch::kFloat) *
                   weight_scale.index({expert, torch::indexing::Slice(), 0});
        expected.index_put_({0, topk_idx, torch::indexing::Slice()},
                            ref.to(torch::kBFloat16));
    }
    return expected.contiguous();
}

void run_probe(const torch::Tensor& raw_weight,
               const torch::Tensor& shuffled_weight,
               const torch::Tensor& weight_scale,
               const SortedTokens& sorted,
               int64_t k_index)
{
    auto fp8_opts = torch::TensorOptions()
                       .device(torch::kCUDA)
                       .dtype(c10::ScalarType::Float8_e4m3fn);
    auto input = torch::zeros({kTokens, kHidden},
                              torch::TensorOptions().device(torch::kCUDA).dtype(torch::kFloat));
    input.index_put_({0, k_index}, 1.0f);
    input = input.to(c10::ScalarType::Float8_e4m3fn).contiguous();
    require(input.scalar_type() == fp8_opts.dtype(), "input must be fp8");

    auto a_scale = torch::ones({kTokens, 1},
                               torch::TensorOptions().device(torch::kCUDA).dtype(torch::kFloat));
    auto output = torch::empty({kTokens, kTopK, kOutChannels},
                               torch::TensorOptions()
                                   .device(torch::kCUDA)
                                   .dtype(torch::kBFloat16));

    auto returned = aiter::native::moe_c_moe_gemm_marlin_w8a8_fp8(input,
                                                                  shuffled_weight,
                                                                  output,
                                                                  a_scale,
                                                                  weight_scale,
                                                                  std::nullopt,
                                                                  sorted.sorted_token_ids,
                                                                  sorted.expert_ids,
                                                                  sorted.num_tokens_post_pad,
                                                                  kTopK,
                                                                  kMode,
                                                                  kTopK,
                                                                  kKeySelected);
    require(returned.data_ptr() == output.data_ptr(), "moe_c return alias mismatch");
    require(hipDeviceSynchronize() == hipSuccess, "moe_c synchronize failed");

    auto expected = make_reference(raw_weight, weight_scale, k_index);
    auto diff = (output.to(torch::kFloat) - expected.to(torch::kFloat)).abs();
    const float max_abs = diff.max().item<float>();
    require(max_abs <= 1e-3f,
            "moe_c gemm1 mismatch at k=" + std::to_string(k_index) +
                ", max_abs=" + std::to_string(max_abs));
    std::cout << "passed moe_c gemm1 k=" << k_index << " max_abs=" << max_abs << "\n";
}

} // namespace

int main()
{
    if(!torch::cuda::is_available())
    {
        std::cerr << "CUDA/HIP device is not available\n";
        return 1;
    }

    torch::manual_seed(20260701);
    auto int_opts = torch::TensorOptions().dtype(torch::kInt32).device(torch::kCUDA);
    auto fp_opts = torch::TensorOptions().dtype(torch::kFloat).device(torch::kCUDA);

    auto topk_ids = torch::arange(0, kTopK, int_opts).view({kTokens, kTopK}).contiguous();
    auto topk_weights = torch::ones({kTokens, kTopK}, fp_opts) / static_cast<float>(kTopK);
    auto sorted = make_sorted_tokens(topk_ids, topk_weights);

    auto raw_weight = torch::randint(-128,
                                     127,
                                     {kExperts, kOutChannels, kHidden},
                                     int_opts)
                          .to(c10::ScalarType::Float8_e4m3fn)
                          .contiguous();
    auto shuffled_weight = moe_layout_shuffle_gemm2(raw_weight).contiguous();
    auto weight_scale =
        (torch::rand({kExperts, kOutChannels, 1}, fp_opts) * 0.02 + 0.001).contiguous();

    const std::vector<int64_t> k_indices = {0, 64, 127, kHidden - 1};
    for(int64_t k_index : k_indices)
    {
        run_probe(raw_weight, shuffled_weight, weight_scale, sorted, k_index);
    }

    std::cout << "all libtorch moe_c fp8 tests passed\n";
    return 0;
}
