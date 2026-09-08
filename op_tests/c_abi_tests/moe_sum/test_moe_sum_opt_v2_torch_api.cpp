// SPDX-License-Identifier: MIT

#include "moe_c_sum.h"

#include <hip/hip_runtime.h>
#include <torch/torch.h>

#include <iostream>
#include <stdexcept>
#include <string>

namespace {

void require(bool ok, const std::string& message)
{
    if(!ok) throw std::runtime_error(message);
}

} // namespace

int main()
{
    require(torch::cuda::is_available(), "CUDA/HIP device is not available");
    torch::manual_seed(20260902);
    constexpr int64_t tokens = 257;
    constexpr int64_t topk = 8;
    constexpr int64_t hidden = 768;
    constexpr double scale = 0.75;
    auto opts = torch::TensorOptions().device(torch::kCUDA).dtype(torch::kHalf);
    auto input = (torch::randn({tokens, topk, hidden}, opts) / 8.0).contiguous();
    auto output = torch::empty({tokens, hidden}, opts);

    auto returned = moe_c_sum_moe_sum_opt_v2(input, output, scale);
    require(hipDeviceSynchronize() == hipSuccess, "moe sum device synchronization failed");
    require(returned.data_ptr() == output.data_ptr(), "moe sum did not return the supplied output tensor");

    auto reference = (input.to(torch::kFloat).sum(1) * scale).to(torch::kHalf);
    const double max_abs = (output.to(torch::kFloat) - reference.to(torch::kFloat)).abs().max().item<double>();
    require(torch::allclose(output, reference, 2e-2, 2e-2, true),
            "moe_c_sum_moe_sum_opt_v2 mismatch, max_abs=" + std::to_string(max_abs));
    require(torch::isfinite(output).all().item<bool>(), "moe sum produced NaN/Inf");
    std::cout << "moe_c_sum_moe_sum_opt_v2 passed max_abs=" << max_abs << "\n";
    return 0;
}
