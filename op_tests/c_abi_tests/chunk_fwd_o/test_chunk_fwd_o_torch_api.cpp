// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.

#include "aiter_c_ops.h"

#include <hip/hip_runtime.h>
#include <torch/script.h>
#include <torch/torch.h>

#include <cmath>
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
    if(!torch::allclose(actual, expected, 8e-2, 8e-2, true))
    {
        const double max_abs = (actual.to(torch::kFloat) - expected.to(torch::kFloat))
                                   .abs()
                                   .max()
                                   .item<double>();
        throw std::runtime_error(std::string("C++ API ") + name +
                                 " mismatch, max_abs=" + std::to_string(max_abs));
    }
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
    auto fixture = torch::jit::load((root / "fixture.pt").string(), torch::kCUDA);
    auto q = load(fixture, "q");
    auto k = load(fixture, "k");
    auto v = load(fixture, "v");
    auto h = load(fixture, "h");
    auto g = load(fixture, "g");
    auto g_gamma = load(fixture, "g_gamma");
    auto cu_seqlens = load(fixture, "cu_seqlens");
    auto chunk_indices = load(fixture, "chunk_indices");

    const double scale = 1.0 / std::sqrt(static_cast<double>(k.size(3)));
    auto output = aiter::native::chunk_fwd_o_vllm_hip_blockdim64(
        q,
        k,
        v,
        h,
        std::optional<torch::Tensor>(g),
        std::optional<torch::Tensor>(g_gamma),
        scale,
        std::optional<torch::Tensor>(cu_seqlens),
        std::optional<torch::Tensor>(chunk_indices),
        64,
        false,
        true);
    if(hipDeviceSynchronize() != hipSuccess)
    {
        throw std::runtime_error("hipDeviceSynchronize failed");
    }

    check_close("o", output, load(fixture, "expected_o"));
    std::cout << "chunk_fwd_o_vllm_hip_blockdim64 LibTorch C++ API passed\n";
    return 0;
}
