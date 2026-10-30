// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
// SPDX-License-Identifier: MIT
#pragma once

#include <torch/extension.h>

namespace aiter {

// Row-wise reduce-sum along the last dimension:
//   input: [..., D] contiguous (or last-dim contiguous)
//   out:   [...], same dtype as input
// waves_per_block: number of waves per block (= rows per block).
//   -1 -> auto select (arch-specific: gfx938 tuned / gfx946 provisional).
// Host dispatches gfx938 vs gfx946 kernels via GPU_ARCHS / GPU_CHIP / gcnArchName.
void reduce_sum(torch::Tensor& out,
                torch::Tensor& input,
                int64_t waves_per_block = -1);

} // namespace aiter
