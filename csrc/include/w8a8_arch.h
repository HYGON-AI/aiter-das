// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
#pragma once

#include <ATen/hip/HIPContext.h>
#include <torch/extension.h>
#include <string>

// Check the input device, not the current device or the build's GPU_ARCHS list:
// a fat binary may contain both gfx936 INT8 and gfx938 FP8 kernels.
inline void check_w8a8_fp8_device(const torch::Tensor& input)
{
#if AITER_W8A8_HCU
    const auto* props = at::cuda::getDeviceProperties(input.get_device());
    const std::string full_arch = props->gcnArchName;
    const std::string arch = full_arch.substr(0, full_arch.find(':'));
    TORCH_CHECK(arch == "gfx92a" || arch == "gfx938" || arch == "gfx946",
                "W8A8 CK FP8 requires gfx92a, gfx938 or gfx946; got ", arch,
                ". gfx936 supports rowwise INT8 only.");
#endif
}
