// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#include "aiter_c_ops.h"

#include <hip/hip_runtime.h>
#include <torch/script.h>
#include <torch/torch.h>

#include <filesystem>
#include <iostream>
#include <optional>
#include <stdexcept>
#include <string>

namespace {

torch::Tensor load(const torch::jit::Module& fixture, const char* name)
{
    return fixture.attr(name).toTensor();
}

void check_close(const char* name, const torch::Tensor& actual, const torch::Tensor& expected)
{
    if(!torch::allclose(actual, expected, 8e-2, 8e-2, false))
    {
        const auto diff = (actual.to(torch::kFloat) - expected.to(torch::kFloat)).abs();
        const double max_abs = diff.max().item<double>();
        const double mean_abs = diff.mean().item<double>();
        throw std::runtime_error(std::string("C++ API ") + name +
                                 " mismatch, max_abs=" + std::to_string(max_abs) +
                                 ", mean_abs=" + std::to_string(mean_abs));
    }
    if(!torch::isfinite(actual.to(torch::kFloat)).all().item<bool>())
    {
        throw std::runtime_error(std::string("C++ API ") + name + " contains NaN or Inf");
    }
}

void run_case(
    const torch::jit::Module& fixture,
    const char* prefix,
    const std::optional<torch::Tensor>& cu_seqlens,
    const std::optional<torch::Tensor>& chunk_indices)
{
    const auto k = load(fixture, (std::string(prefix) + "_k").c_str());
    const auto beta = load(fixture, (std::string(prefix) + "_beta").c_str());
    const auto g = load(fixture, (std::string(prefix) + "_g").c_str());
    const auto expected = load(fixture, (std::string(prefix) + "_expected").c_str());

    const auto actual = aiter::native::chunk_gated_delta_rule_fwd_kkt_solve_hip(
        k, beta, g, cu_seqlens, chunk_indices, 64);
    if(hipDeviceSynchronize() != hipSuccess)
    {
        throw std::runtime_error("hipDeviceSynchronize failed");
    }

    check_close(prefix, actual, expected);
    std::cout << "chunk_gated_delta_rule_fwd_kkt_solve_hip " << prefix
              << " LibTorch C++ API passed\n";
}

} // namespace

int main(int argc, char** argv)
{
    if(argc != 2)
    {
        std::cerr << "usage: " << argv[0] << " FIXTURE_DIR\n";
        return 2;
    }
    if(!torch::cuda::is_available())
    {
        std::cerr << "HIP device is not available\n";
        return 1;
    }

    const std::filesystem::path root(argv[1]);
    const auto fixture = torch::jit::load((root / "fixture.pt").string(), torch::kCUDA);

    run_case(fixture, "dense", std::nullopt, std::nullopt);
    run_case(
        fixture,
        "varlen",
        load(fixture, "varlen_cu_seqlens"),
        load(fixture, "varlen_chunk_indices"));
    return 0;
}
