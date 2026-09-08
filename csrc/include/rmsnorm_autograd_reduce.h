// SPDX-License-Identifier: MIT
#pragma once

#include <ATen/AccumulateType.h>
#include <c10/cuda/CUDAMathCompat.h>
#include <c10/macros/Macros.h>
#include <torch/extension.h>

namespace aiter {
namespace rmsnorm_autograd {

template <typename scalar_t, int vec_size>
struct alignas(sizeof(scalar_t) * vec_size) aligned_vector
{
    scalar_t val[vec_size];
};

constexpr int kColwiseReduceTileSize = 32;

template <typename T>
__inline__ __device__ T warp_shfl_down(T val, int offset)
{
    return __shfl_down(val, offset);
}

template <typename T>
__inline__ __device__ T WarpReduceSum(T val, int max = 32)
{
    for(int offset = max; offset > 0; offset >>= 1)
    {
        val += warp_shfl_down(val, offset);
    }
    return val;
}

template <typename T, int max>
__inline__ __device__ T WarpReduceSum(T val)
{
#pragma unroll
    for(int offset = max; offset > 0; offset >>= 1)
    {
        val += warp_shfl_down(val, offset);
    }
    return val;
}

template <typename T>
__inline__ __device__ T BlockReduceSum(T val, T* shared)
{
    const int lid        = threadIdx.x % C10_WARP_SIZE;
    const int wid        = threadIdx.x / C10_WARP_SIZE;
    const int block_size = blockDim.x;
    const int share_size = block_size / C10_WARP_SIZE;
    val                  = WarpReduceSum<T, 32>(val);
    if(block_size == C10_WARP_SIZE)
        return val;
    if(lid == 0 && wid < share_size)
    {
        shared[wid] = val;
    }
    __syncthreads();
    if(wid == 0 && lid < share_size)
    {
        val = shared[lid];
        val = WarpReduceSum(val, share_size / 2);
    }
    return val;
}

template <typename T, int share_size>
__inline__ __device__ T BlockReduceSum(T val, T* shared)
{
    const int lid = threadIdx.x % C10_WARP_SIZE;
    const int wid = threadIdx.x / C10_WARP_SIZE;
    val           = WarpReduceSum<T, 32>(val);
    if constexpr(share_size == 1)
    {
        return val;
    }
    else
    {
        if(lid == 0 && wid < share_size)
        {
            shared[wid] = val;
        }
        __syncthreads();
        if(wid == 0 && lid < share_size)
        {
            val = shared[lid];
            val = WarpReduceSum<T, share_size / 2>(val);
        }
        return val;
    }
}

} // namespace rmsnorm_autograd
} // namespace aiter
