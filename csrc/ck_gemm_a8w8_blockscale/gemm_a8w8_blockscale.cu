// SPDX-License-Identifier: MIT
// Copyright (C) 2024-2026, Advanced Micro Devices, Inc. All rights reserved.
 

#include "gemm_a8w8_blockscale_common.cuh"
#include "gemm_a8w8_blockscale_manifest.h"
#include "gemm_a8w8_blockscale_lookup.h"
#include <cmath>
#include <climits>
#include "py_itfs_common.h"
#include "w8a8_arch.h"

namespace {
struct E8M0ScaleArgs
{
    const uint8_t* a;
    const uint8_t* b;
    float* decoded_a;
    float* decoded_b;
    int a_size;
    int b_size;
};

// CK's legacy scale-copy path requires FP32 buffers. Decode the compact
// exponents once on the caller's stream; retain the 32-element scale grouping.
__global__ void w8a8_decode_e8m0_scales(E8M0ScaleArgs args)
{
    const int i = blockIdx.x * blockDim.x + threadIdx.x;
    if(i < args.a_size)
        args.decoded_a[i] = static_cast<float>(ck::e8m0_bexp_t(args.a[i]));
    else if(i - args.a_size < args.b_size)
        args.decoded_b[i - args.a_size] = static_cast<float>(ck::e8m0_bexp_t(args.b[i - args.a_size]));
}
} // namespace
   
using BlockwiseKernel = std::function<
    torch::Tensor(torch::Tensor &, torch::Tensor &,
                  torch::Tensor &, torch::Tensor &, 
                  torch::Tensor &)>; 

// Define a custom hash function for std::tuple<int, int, int>
struct IntTupleHash
{
  size_t operator()(const std::tuple<int, int, int> &t) const
  {
    auto hash1 = std::hash<int>{}(std::get<0>(t));
    auto hash2 = std::hash<int>{}(std::get<1>(t));
    auto hash3 = std::hash<int>{}(std::get<2>(t));
    return hash1 ^ hash2 ^ hash3;
  }
};

using BlockwiseKernelMap = std::unordered_map<
    std::tuple<int, int, int>,
    BlockwiseKernel, 
    IntTupleHash>;

// Helper function to return the next largest power of 2
static constexpr int nextPow2(unsigned int num)
{
  if (num <= 1)
    return 1;
  return 1 << (CHAR_BIT * sizeof(num) - __builtin_clz(num - 1));
}

template <typename DDataType, typename EDataType = DDataType>
BlockwiseKernel blockscale_dispatch(int M, int N, int K)
{
#if AITER_W8A8_HCU
    // ScaleBlockM=1: keep one M XDL per wave to limit scale/accumulator
    // state, and distribute larger M over more waves instead.
    if(M >= 64 && N >= 64)
        return a8w8_blockscale_1x128x128_256x64x64x128_16x16_16x16_8x32x1_8x32x1_1x64x1x4_4_1x1_intrawave_v1<DDataType, EDataType>;
    if(M >= 16 && N >= 32)
        return a8w8_blockscale_1x128x128_64x16x32x128_16x16_16x16_8x8x1_8x8x1_1x16x1x4_4_1x1_intrawave_v1<DDataType, EDataType>;
    return a8w8_blockscale_1x128x128_64x16x16x128_16x16_16x16_8x8x1_8x8x1_1x16x1x4_4_1x1_intrawave_v1<DDataType, EDataType>;
#else

    // For a given shape, either find the best kernel via lookup or heuristic.
    // For many small M shapes, we bucket them to the next largest kernel.
    // This is fine since kernels are padded anyway.
    
    static const auto lookup = []
    {
      if constexpr (std::is_same_v<EDataType, F16>) {
          return BlockwiseKernelMap{GENERATE_LOOKUP_TABLE(DDataType,F16)};
      } else if constexpr (std::is_same_v<EDataType, B16>) {
          return BlockwiseKernelMap{GENERATE_LOOKUP_TABLE(DDataType,B16)};
      } else {
          static_assert(false, "blockscale_dispatch used with unsupported dtype!");
      } }();
    
    // First check if this shape(M,N,K) is available in the direct lookup.
    auto it = lookup.find({M, N, K});
    // If we found an optimal kernel, use it.
    if (it != lookup.end())
    {
      return it->second;
    }

    int padded_m = M;
    if (M > 1 && M <= 16)
    {
      padded_m = 16;
    }
    else if (M <= 16384)
    {
      padded_m = nextPow2(M);
    }
    else if (M <= 20480)
    {
      padded_m = 20480;
    }
    // Second check if this shape(padded_m,N,K) is available in the direct lookup.
    it = lookup.find({padded_m, N, K});
    // If we found an optimal kernel, use it.
    if (it != lookup.end())
    {
      return it->second;
    }
    // Otherwise, use heuristics.
    return a8w8_blockscale_1x128x128_256x16x128x256_16x16_16x16_16x16x1_16x16x1_1x16x1x16_8_1x2_intrawave_v1<DDataType, EDataType>;
#endif
}

template <typename DDataType, typename EDataType>
BlockwiseKernel mx_dispatch(int M, int N, int K)
{
  // Keep MX scale groups within a wave's N range. Small K uses K128;
  // larger K at small M benefits from the K256 tile. Tiny M keeps K128.
  if(M >= 64 && N >= 32)
    return a8w8_blockscale_1x32x32_256x64x32x128_8x8_16x16_16x16x1_16x16x1_1x64x1x4_4_1x1_intrawave_v1<DDataType, EDataType>;
  if(M >= 16)
  {
    if(N >= 8192 || K <= 128)
      return a8w8_blockscale_1x32x32_64x16x32x128_8x8_16x16_16x4x1_16x4x1_1x16x1x4_4_1x1_intrawave_v1<DDataType, EDataType>;
    return a8w8_blockscale_1x32x32_64x16x16x256_8x8_16x16_32x2x1_32x2x1_1x16x1x4_4_1x1_intrawave_v1<DDataType, EDataType>;
  }
  return a8w8_blockscale_1x32x32_64x16x16x128_8x8_16x16_16x4x1_16x4x1_1x16x1x4_4_1x1_intrawave_v1<DDataType, EDataType>;
}

torch::Tensor gemm_a8w8_blockscale(
    torch::Tensor& XQ,
    torch::Tensor& WQ,
    torch::Tensor& x_scale,
    torch::Tensor& w_scale,
    torch::Tensor& Y)
{
    TORCH_CHECK(XQ.dim() == 2 && WQ.dim() == 2 && Y.dim() == 2 &&
                    x_scale.dim() == 2 && w_scale.dim() == 2, "W8A8 blockscale requires 2D tensors");
    TORCH_CHECK(XQ.size(1) == WQ.size(1) && XQ.size(1) > 0 && WQ.size(0) > 0 &&
                    Y.size(0) == XQ.size(0) && Y.size(1) == WQ.size(0), "W8A8 shape mismatch");
    for (const auto& tensor : {XQ, WQ, x_scale, w_scale, Y})
      TORCH_CHECK(tensor.is_cuda() && tensor.device() == XQ.device() && tensor.is_contiguous(),
                  "W8A8 tensors must be contiguous on the same HIP device");
    TORCH_CHECK(XQ.numel() <= INT_MAX && WQ.numel() <= INT_MAX && Y.numel() <= INT_MAX,
                "W8A8 exceeds CK 32-bit indexing capacity");
    const int group = x_scale.scalar_type() == at::ScalarType::Byte ? 32 : 128;
    TORCH_CHECK(x_scale.size(0) == XQ.size(0) && x_scale.size(1) == (XQ.size(1)+group-1)/group &&
                    w_scale.size(0) == (WQ.size(0)+group-1)/group && w_scale.size(1) == x_scale.size(1),
                "W8A8 blockscale scale shape mismatch");
    TORCH_CHECK(XQ.dtype() == WQ.dtype(), "Weights and activations should have the same dtype!");
    TORCH_CHECK(XQ.dtype() == torch_fp8, "blockscale requires FP8 E4M3FN inputs");
    TORCH_CHECK(x_scale.dtype() == w_scale.dtype(),
                "Scales should have the same dtype!");
    if (XQ.size(0) == 0) return Y;
    check_w8a8_fp8_device(XQ);

  int M = XQ.size(0);
  int N = WQ.size(0);
  int K = XQ.size(1);

  if (x_scale.dtype() == at::ScalarType::Byte)
  {
    const at::hip::OptionalHIPGuardMasqueradingAsCUDA device_guard(device_of(XQ));
    auto decoded_a = torch::empty(x_scale.sizes(), x_scale.options().dtype(at::ScalarType::Float));
    auto decoded_b = torch::empty(w_scale.sizes(), w_scale.options().dtype(at::ScalarType::Float));
    E8M0ScaleArgs args{ x_scale.data_ptr<uint8_t>(), w_scale.data_ptr<uint8_t>(),
                       decoded_a.data_ptr<float>(), decoded_b.data_ptr<float>(),
                       static_cast<int>(x_scale.numel()), static_cast<int>(w_scale.numel()) };
    ck::launch_and_time_multidie_kernel(ck::launch_policy::w8a8,
        StreamConfig{at::hip::getCurrentHIPStreamMasqueradingAsCUDA().stream()},
        w8a8_decode_e8m0_scales, dim3((args.a_size + args.b_size + 255) / 256), dim3(256), 0, args);
    if (Y.dtype() == at::ScalarType::Half)
      mx_dispatch<F32, F16>(M, N, K)(XQ, WQ, decoded_a, decoded_b, Y);
    else if (Y.dtype() == at::ScalarType::BFloat16)
      mx_dispatch<F32, B16>(M, N, K)(XQ, WQ, decoded_a, decoded_b, Y);
    else
      TORCH_CHECK(false, "Unsupported MX output dtype");
  }
  else if (x_scale.dtype() == at::ScalarType::Float && Y.dtype() == at::ScalarType::Half)
  {
    blockscale_dispatch<F32, F16>(M, N, K)(XQ, WQ, x_scale, w_scale, Y);
  }
  else if (x_scale.dtype() == at::ScalarType::Float && Y.dtype() == at::ScalarType::BFloat16)
  {
    blockscale_dispatch<F32, B16>(M, N, K)(XQ, WQ, x_scale, w_scale, Y);
  }
  else
  {
    TORCH_CHECK(false, "Unsupported scales/output dtype!");
  }
  return Y;
}
