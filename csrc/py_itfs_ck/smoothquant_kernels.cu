// SPDX-License-Identifier: MIT
// Copyright (C) 2024-2025, Advanced Micro Devices, Inc. All rights reserved.
 
#include <torch/all.h>
#include <ATen/hip/HIPContext.h>
#include <ATen/hip/impl/HIPGuardImplMasqueradingAsCUDA.h>
#include "py_itfs_common.h"

#include "ck_tile/host/kernel_launch.hpp"
#include "ck_tile/ops/smoothquant.hpp"

namespace {

template <typename XDataType>
void launch_smoothquant_int8(torch::Tensor& out,
                             torch::Tensor& input,
                             torch::Tensor& x_scale,
                             torch::Tensor& y_scale,
                             hipStream_t stream)
{
    using XScaleDataType  = float;
    using YScaleDataType  = float;
    using QYDataType      = ck_tile::int8_t;
    using ComputeDataType = float;

    using BlockWarps = ck_tile::sequence<2, 2>;
    using BlockTile  = ck_tile::sequence<2, 128>;
    using WarpTile   = ck_tile::sequence<1, 64>;
    using Vector     = ck_tile::sequence<1, 1>;
    using Shape = ck_tile::Generic2dBlockShape<BlockTile, BlockWarps, WarpTile, Vector>;
    using Problem = ck_tile::SmoothquantPipelineProblem<XDataType,
                                                        XScaleDataType,
                                                        ComputeDataType,
                                                        YScaleDataType,
                                                        QYDataType,
                                                        Shape,
                                                        true,
                                                        true>;
    using Pipeline = ck_tile::SmoothquantPipelineTwoPass<Problem>;
    using Kernel   = ck_tile::Smoothquant<Pipeline>;

    const ck_tile::index_t n = input.size(-1);
    const ck_tile::index_t m = input.numel() / n;
    const ck_tile::SmoothquantHostArgs args{input.data_ptr(),
                                             x_scale.data_ptr(),
                                             y_scale.data_ptr(),
                                             out.data_ptr(),
                                             m,
                                             n,
                                             static_cast<ck_tile::index_t>(input.stride(0))};
    const auto kargs       = Kernel::MakeKargs(args);
    const dim3 grid        = Kernel::GridSize(args);
    constexpr dim3 block   = Kernel::BlockSize();
    constexpr int occupancy = 1;

    (void)ck_tile::launch_kernel(
        ck_tile::stream_config{stream},
        ck_tile::make_kernel<block.x, occupancy>(Kernel{}, grid, block, 0, kargs));
}

template <typename XDataType>
void launch_moe_smoothquant_int8(torch::Tensor& out,
                                 torch::Tensor& input,
                                 torch::Tensor& x_scale,
                                 torch::Tensor& topk_ids,
                                 torch::Tensor& y_scale,
                                 hipStream_t stream)
{
    using SmoothScaleDataType = float;
    using YScaleDataType      = float;
    using QYDataType          = ck_tile::int8_t;
    using ComputeDataType     = float;

    using BlockWarps = ck_tile::sequence<2, 2>;
    using BlockTile  = ck_tile::sequence<2, 128>;
    using WarpTile   = ck_tile::sequence<1, 64>;
    using Vector     = ck_tile::sequence<1, 1>;
    using Shape = ck_tile::Generic2dBlockShape<BlockTile, BlockWarps, WarpTile, Vector>;
    using Problem = ck_tile::SmoothquantPipelineProblem<XDataType,
                                                        SmoothScaleDataType,
                                                        ComputeDataType,
                                                        YScaleDataType,
                                                        QYDataType,
                                                        Shape,
                                                        false,
                                                        true>;
    using Pipeline = ck_tile::SmoothquantPipelineTwoPass<Problem>;
    using Kernel   = ck_tile::MoeSmoothquant<Pipeline>;

    const auto tokens  = static_cast<ck_tile::index_t>(input.size(0));
    const auto hidden  = static_cast<ck_tile::index_t>(input.size(1));
    const auto experts = static_cast<ck_tile::index_t>(x_scale.size(0));
    const auto topk    = static_cast<ck_tile::index_t>(topk_ids.size(1));
    const ck_tile::MoeSmoothquantHostArgs args{
        input.data_ptr(),
        x_scale.data_ptr(),
        topk_ids.data_ptr(),
        y_scale.data_ptr(),
        out.data_ptr(),
        tokens,
        hidden,
        experts,
        topk,
        static_cast<ck_tile::index_t>(input.stride(0)),
        static_cast<ck_tile::index_t>(out.stride(0))};
    const auto kargs       = Kernel::MakeKargs(args);
    const dim3 grid        = Kernel::GridSize(args);
    constexpr dim3 block   = Kernel::BlockSizeValue();
    constexpr int occupancy = 1;

    (void)ck_tile::launch_kernel(
        ck_tile::stream_config{stream},
        ck_tile::make_kernel<block.x, occupancy>(Kernel{}, grid, block, 0, kargs));
}

} // namespace

void smoothquant_fwd(torch::Tensor &out,     // [m ,n]
                     torch::Tensor &input,   // [m ,n]
                     torch::Tensor &x_scale, // [1 ,n]
                     torch::Tensor &y_scale) // [m ,1]
{
    auto dtype = input.dtype();
    TORCH_CHECK(dtype == torch::kFloat16 || dtype == torch::kBFloat16,
                "ck smoothquant only support fp16 and bf16 data type");
    TORCH_CHECK(out.dtype() == torch::kChar,
                "ck smoothquant_fwd currently supports int8 output only");
    TORCH_CHECK(input.dim() == 2 && input.is_contiguous(),
                "ck smoothquant_fwd expects contiguous 2D input");
    TORCH_CHECK(out.sizes() == input.sizes() && out.is_contiguous(),
                "ck smoothquant_fwd expects contiguous output with input shape");
    TORCH_CHECK(x_scale.dtype() == torch::kFloat32 && x_scale.numel() == input.size(-1) &&
                    x_scale.is_contiguous(),
                "ck smoothquant_fwd expects contiguous fp32 x_scale with N elements");
    TORCH_CHECK(y_scale.dtype() == torch::kFloat32 &&
                    y_scale.numel() == input.size(0) && y_scale.is_contiguous(),
                "ck smoothquant_fwd expects contiguous fp32 y_scale with M elements");

    const at::hip::OptionalHIPGuardMasqueradingAsCUDA device_guard(device_of(input));
    const hipStream_t stream = at::hip::getCurrentHIPStream();
    if(dtype == torch::kFloat16)
        launch_smoothquant_int8<ck_tile::half_t>(out, input, x_scale, y_scale, stream);
    else
        launch_smoothquant_int8<ck_tile::bf16_t>(out, input, x_scale, y_scale, stream);
}

void moe_smoothquant_fwd(torch::Tensor &out,      // [topk * tokens, hidden_size]
                         torch::Tensor &input,    // [tokens, hidden_size]
                         torch::Tensor &x_scale,  // [experts, hidden_size]
                         torch::Tensor &topk_ids, // [tokens, topk]
                         torch::Tensor &y_scale)  // [topk * tokens,  1]
{
    const auto dtype = input.dtype();
    TORCH_CHECK(dtype == torch::kFloat16 || dtype == torch::kBFloat16,
                "ck moe_smoothquant_fwd supports fp16 and bf16 input only");
    TORCH_CHECK(out.dtype() == torch::kChar,
                "ck moe_smoothquant_fwd currently supports int8 output only");
    TORCH_CHECK(input.dim() == 2 && input.is_contiguous(),
                "ck moe_smoothquant_fwd expects contiguous [tokens, hidden] input");
    TORCH_CHECK(input.size(0) > 0 && input.size(0) % 2 == 0,
                "ck moe_smoothquant_fwd requires a positive even token count");
    TORCH_CHECK(input.size(1) > 0 && input.size(1) % 128 == 0,
                "ck moe_smoothquant_fwd requires hidden size divisible by 128");
    TORCH_CHECK(x_scale.dim() == 2 && x_scale.dtype() == torch::kFloat32 &&
                    x_scale.size(0) > 0 && x_scale.size(1) == input.size(1) &&
                    x_scale.is_contiguous(),
                "ck moe_smoothquant_fwd expects contiguous fp32 [experts, hidden] x_scale");
    TORCH_CHECK(topk_ids.dim() == 2 && topk_ids.dtype() == torch::kInt32 &&
                    topk_ids.size(0) == input.size(0) && topk_ids.size(1) > 0 &&
                    topk_ids.is_contiguous(),
                "ck moe_smoothquant_fwd expects contiguous int32 [tokens, topk] ids");
    TORCH_CHECK(out.dim() == 2 && out.size(0) == input.size(0) * topk_ids.size(1) &&
                    out.size(1) == input.size(1) && out.is_contiguous(),
                "ck moe_smoothquant_fwd expects contiguous [topk * tokens, hidden] output");
    TORCH_CHECK(y_scale.dtype() == torch::kFloat32 &&
                    y_scale.numel() == input.size(0) * topk_ids.size(1) &&
                    y_scale.is_contiguous(),
                "ck moe_smoothquant_fwd expects contiguous fp32 [topk * tokens] y_scale");
    TORCH_CHECK(out.device() == input.device() && x_scale.device() == input.device() &&
                    topk_ids.device() == input.device() && y_scale.device() == input.device(),
                "ck moe_smoothquant_fwd expects all tensors on the same device");

    const at::hip::OptionalHIPGuardMasqueradingAsCUDA device_guard(device_of(input));
    const hipStream_t stream = at::hip::getCurrentHIPStream();
    if(dtype == torch::kFloat16)
        launch_moe_smoothquant_int8<ck_tile::half_t>(
            out, input, x_scale, topk_ids, y_scale, stream);
    else
        launch_moe_smoothquant_int8<ck_tile::bf16_t>(
            out, input, x_scale, topk_ids, y_scale, stream);
}
