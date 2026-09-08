// SPDX-License-Identifier: MIT

#include "rmsnorm_autograd_kernels.h"

#include <ATen/hip/HIPContext.h>
#include <ATen/hip/impl/HIPGuardImplMasqueradingAsCUDA.h>
#include <torch/all.h>

namespace aiter {
namespace rmsnorm_autograd {

namespace {

constexpr int VEC = 4;

// Small-shape threshold: use multi-row kernels to cut grid size / launch overhead.
constexpr int kSmallRowsMultiRow = 512;

int get_layernorm_blocksize(int cols)
{
    if(cols > 256)
        return 512;
    if(cols > 128)
        return 256;
    if(cols > 64)
        return 128;
    return 64;
}

inline int get_vec_backward_block_size(int N, int VEC, int max_block)
{
    const int tcol  = N / VEC;
    const int block = ((tcol + 63) / 64) * 64;
    return block > max_block ? max_block : (block < 64 ? 64 : block);
}

inline int pick_small_rows_per_block(int rows, int max_rows_per_block = 16)
{
    if(rows <= 64)
    {
        return 8;
    }
    if(rows <= 256)
    {
        return max_rows_per_block;
    }
    return 8;
}

template <typename scalar_t>
void Gamma_Backward(int length,
                    int N,
                    scalar_t* dY_data,
                    scalar_t* X_data,
                    float* rstd_data,
                    scalar_t* dgamma_data,
                    hipStream_t stream)
{
    using T_ACC = at::acc_type<scalar_t, true>;
    int M       = length / N;
    const int B = (N - 1) / kColwiseReduceTileSize + 1;
    if(N <= 512 && M >= 4096)
    {
        int part_size = 64;
        c10::TensorOptions options(c10::DeviceType::CUDA);
        options = options.dtype(c10::ScalarType::Float);
        at::Tensor part_grad_gamma = at::empty({N, part_size}, options);
        T_ACC* pd_gamma             = part_grad_gamma.template data_ptr<T_ACC>();
        g_backward_kernel_part_a<<<dim3(B, part_size),
                                   dim3(kColwiseReduceTileSize, kColwiseReduceTileSize),
                                   0,
                                   stream>>>(M, N, dY_data, X_data, rstd_data, pd_gamma);
        g_backward_kernel_part_b<<<N, part_size, 0, stream>>>(pd_gamma, dgamma_data);
    }
    else
    {
        GammaBackward<scalar_t><<<B,
                                  dim3(kColwiseReduceTileSize, kColwiseReduceTileSize),
                                  0,
                                  stream>>>(M, N, dY_data, X_data, rstd_data, dgamma_data);
    }
}

template <typename scalar_t, int VEC = 4>
__global__ void __launch_bounds__(512, 2) rmsnorm_forward_kernel(scalar_t* input,
                                                                 scalar_t* ret,
                                                                 float* rstd,
                                                                 scalar_t* gamma,
                                                                 int cols,
                                                                 scalar_t eps)
{
    int blockidx    = blockIdx.x;
    int threadidx   = threadIdx.x;
    int block_cols  = blockidx * cols;
    using T_ACC     = at::acc_type<scalar_t, true>;
    __shared__ T_ACC val_shared[16];
    __shared__ T_ACC s_rstd;
    using VecTpye = aiter::rmsnorm_autograd::aligned_vector<scalar_t, VEC>;
    const VecTpye* X = reinterpret_cast<const VecTpye*>(input + block_cols);
    VecTpye* Y       = reinterpret_cast<VecTpye*>(ret + block_cols);
    int tcol      = cols / VEC;
    T_ACC val     = 0;
    T_ACC trstd;
    VecTpye tx;
    VecTpye ty;
    scalar_t* px = (scalar_t*)(&tx);
    scalar_t* py = (scalar_t*)(&ty);
    for(int j = threadidx; j < tcol; j += blockDim.x)
    {
        tx = X[j];
#pragma unroll
        for(int i = 0; i < VEC; i++)
        {
            val += static_cast<T_ACC>(px[i]) * static_cast<T_ACC>(px[i]);
        }
    }
    val = BlockReduceSum(val, val_shared);
    if(threadidx == 0)
    {
        s_rstd = c10::cuda::compat::rsqrt(val / cols + static_cast<T_ACC>(eps));
    }
    __syncthreads();
    trstd = s_rstd;
    for(int j = threadidx; j < tcol; j += blockDim.x)
    {
        tx = X[j];
#pragma unroll
        for(int i = 0; i < VEC; i++)
        {
            int jj  = j * VEC + i;
            py[i]   = static_cast<T_ACC>(px[i]) * static_cast<T_ACC>(gamma[jj]) * trstd;
        }
        Y[j] = ty;
    }
    if(threadIdx.x == 0 && rstd != NULL)
    {
        rstd[blockidx] = trstd;
    }
}

// Multi-row forward kernel for small M: each warp (64 threads) handles one row.
// Uses warp-level reduction (shuffle) instead of block-level to eliminate one
// __syncthreads() barrier and improve occupancy when row count is small.
template <typename scalar_t, int VEC = 4, int ROWS_PER_BLOCK = 8>
__global__ void __launch_bounds__(ROWS_PER_BLOCK * 64, 2)
rmsnorm_forward_kernel_multi_row(scalar_t* input,
                                  scalar_t* ret,
                                  float* rstd,
                                  scalar_t* gamma,
                                  int cols,
                                  int rows,
                                  scalar_t eps)
{
    constexpr int WARP         = 64;
    const int row_start        = blockIdx.x * ROWS_PER_BLOCK;
    const int lid              = threadIdx.x % WARP;
    const int wid              = threadIdx.x / WARP;
    const int my_row           = row_start + wid;

    using T_ACC    = at::acc_type<scalar_t, true>;
    using VecTpye  = aiter::rmsnorm_autograd::aligned_vector<scalar_t, VEC>;

    __shared__ T_ACC s_rstd[ROWS_PER_BLOCK];
    const int tcol = cols / VEC;

    T_ACC val   = 0;
    T_ACC trstd = 0;
    VecTpye tx;
    scalar_t* px = (scalar_t*)(&tx);

    // Pass 1: compute sum of squares per row (warp-level reduce)
    if(my_row < rows)
    {
        const VecTpye* X = reinterpret_cast<const VecTpye*>(input + my_row * cols);
        for(int j = lid; j < tcol; j += WARP)
        {
            tx = X[j];
#pragma unroll
            for(int i = 0; i < VEC; i++)
            {
                val += static_cast<T_ACC>(px[i]) * static_cast<T_ACC>(px[i]);
            }
        }
        val = WarpReduceSum<T_ACC, 32>(val);
        if(lid == 0)
        {
            s_rstd[wid] = c10::cuda::compat::rsqrt(
                val / static_cast<T_ACC>(cols) + static_cast<T_ACC>(eps));
        }
    }
    __syncthreads();

    // Pass 2: compute normalized output
    if(my_row < rows)
    {
        trstd                = s_rstd[wid];
        const VecTpye* X     = reinterpret_cast<const VecTpye*>(input + my_row * cols);
        VecTpye* Y           = reinterpret_cast<VecTpye*>(ret + my_row * cols);
        VecTpye ty;
        scalar_t* py = (scalar_t*)(&ty);
        for(int j = lid; j < tcol; j += WARP)
        {
            tx = X[j];
#pragma unroll
            for(int i = 0; i < VEC; i++)
            {
                int jj = j * VEC + i;
                py[i]  = static_cast<T_ACC>(px[i]) * static_cast<T_ACC>(gamma[jj]) * trstd;
            }
            Y[j] = ty;
        }
        if(lid == 0 && rstd != NULL)
        {
            rstd[my_row] = trstd;
        }
    }
}

template <typename scalar_t, int VEC = 4, int blocksize = 512>
__global__ void __launch_bounds__(blocksize, 2) rmsnorm_forward_kernel_fast(scalar_t* input,
                                                                            scalar_t* ret,
                                                                            float* rstd,
                                                                            scalar_t* gamma,
                                                                            int cols,
                                                                            scalar_t eps)
{
    int blockidx   = blockIdx.x;
    int threadidx  = threadIdx.x;
    int block_cols = blockidx * cols;
    using T_ACC    = at::acc_type<scalar_t, true>;
    constexpr int sharesize = blocksize / C10_WARP_SIZE;
    __shared__ T_ACC val_shared[sharesize + 1];
    __shared__ T_ACC s_rstd;
    using VecTpye = aiter::rmsnorm_autograd::aligned_vector<scalar_t, VEC>;

    const VecTpye* X = reinterpret_cast<const VecTpye*>(input + block_cols);
    VecTpye* Y       = reinterpret_cast<VecTpye*>(ret + block_cols);
    int tcol      = cols / VEC;
    T_ACC trstd;
    VecTpye tx;
    VecTpye ty;
    scalar_t* px = (scalar_t*)(&tx);
    scalar_t* py = (scalar_t*)(&ty);
    T_ACC val = 0;
    if constexpr (blocksize <= 512)
    {
        __shared__ VecTpye shared_x[blocksize];
        for(int j = threadidx; j < tcol; j += blockDim.x)
        {
            tx = X[j];
            shared_x[j] = tx;
#pragma unroll
            for(int i = 0; i < VEC; i++)
            {
                val += static_cast<T_ACC>(px[i]) * static_cast<T_ACC>(px[i]);
            }
        }
        val = BlockReduceSum<T_ACC, sharesize>(val, val_shared);
        if(threadidx == 0)
        {
            const T_ACC inv_cols = static_cast<T_ACC>(1) / static_cast<T_ACC>(cols);
            s_rstd               = c10::cuda::compat::rsqrt(val * inv_cols + static_cast<T_ACC>(eps));
        }
        __syncthreads();
        trstd = s_rstd;
        for(int j = threadidx; j < tcol; j += blockDim.x)
        {
            tx = shared_x[j];
            const scalar_t* px = reinterpret_cast<const scalar_t*>(&tx);
#pragma unroll
            for(int i = 0; i < VEC; i++)
            {
                int jj  = j * VEC + i;
                py[i]   = static_cast<T_ACC>(px[i]) * static_cast<T_ACC>(gamma[jj]) * trstd;
            }
            Y[j] = ty;
        }
    }
    else
    {
        for(int j = threadidx; j < tcol; j += blockDim.x)
        {
            tx = X[j];
#pragma unroll
            for(int i = 0; i < VEC; i++)
            {
                val += static_cast<T_ACC>(px[i]) * static_cast<T_ACC>(px[i]);
            }
        }
        val = BlockReduceSum<T_ACC, sharesize>(val, val_shared);
        if(threadidx == 0)
        {
            const T_ACC inv_cols = static_cast<T_ACC>(1) / static_cast<T_ACC>(cols);
            s_rstd               = c10::cuda::compat::rsqrt(val * inv_cols + static_cast<T_ACC>(eps));
        }
        __syncthreads();
        trstd = s_rstd;
        for(int j = threadidx; j < tcol; j += blockDim.x)
        {
            tx = X[j];
            const scalar_t* px = reinterpret_cast<const scalar_t*>(&tx);
#pragma unroll
            for(int i = 0; i < VEC; i++)
            {
                int jj  = j * VEC + i;
                py[i]   = static_cast<T_ACC>(px[i]) * static_cast<T_ACC>(gamma[jj]) * trstd;
            }
            Y[j] = ty;
        }
    }
    if(threadIdx.x == 0 && rstd != NULL)
    {
        rstd[blockidx] = trstd;
    }
}

// Multi-row backward dX kernel for small M: each warp handles one row.
// Uses warp-level shuffle reduction to avoid block-level barriers.
template <typename scalar_t, int VEC = 4, int ROWS_PER_BLOCK = 8>
__global__ void __launch_bounds__(ROWS_PER_BLOCK * 64, 2)
rmsnorm_backward_kernel_multi_row(int N,
                                   const scalar_t* dY,
                                   const scalar_t* X,
                                   const scalar_t* gamma,
                                   const float* rstd,
                                   scalar_t* dX,
                                   int rows)
{
    constexpr int WARP  = 64;
    const int row_start = blockIdx.x * ROWS_PER_BLOCK;
    const int lid       = threadIdx.x % WARP;
    const int wid       = threadIdx.x / WARP;
    const int my_row    = row_start + wid;

    using T_ACC   = at::acc_type<scalar_t, true>;
    using VecTpye = aiter::rmsnorm_autograd::aligned_vector<scalar_t, VEC>;

    __shared__ T_ACC s_b[ROWS_PER_BLOCK];
    const int tcol = N / VEC;

    T_ACC sum1 = 0;
    VecTpye tx, tdy, tgamma;
    scalar_t* px     = (scalar_t*)(&tx);
    scalar_t* pdy    = (scalar_t*)(&tdy);
    scalar_t* pgamma = (scalar_t*)(&tgamma);

    // Pass 1: compute per-row sum (warp-level reduce)
    if(my_row < rows)
    {
        const VecTpye* X_ptr  = reinterpret_cast<const VecTpye*>(X + my_row * N);
        const VecTpye* dY_ptr = reinterpret_cast<const VecTpye*>(dY + my_row * N);
        for(int j = lid; j < tcol; j += WARP)
        {
            tx     = X_ptr[j];
            tdy    = dY_ptr[j];
            tgamma = *(reinterpret_cast<const VecTpye*>(gamma + j * VEC));
#pragma unroll
            for(int i = 0; i < VEC; i++)
            {
                sum1 += static_cast<T_ACC>(pdy[i]) * static_cast<T_ACC>(px[i]) *
                        static_cast<T_ACC>(pgamma[i]);
            }
        }
        sum1 = WarpReduceSum<T_ACC, 32>(sum1);
        if(lid == 0)
        {
            float trstd  = rstd[my_row];
            T_ACC s      = static_cast<T_ACC>(1) / static_cast<T_ACC>(N);
            s_b[wid]     = -sum1 * static_cast<T_ACC>(trstd) * static_cast<T_ACC>(trstd) *
                       static_cast<T_ACC>(trstd) * s;
        }
    }
    __syncthreads();

    // Pass 2: compute output dX
    if(my_row < rows)
    {
        T_ACC b              = s_b[wid];
        float trstd          = rstd[my_row];
        const VecTpye* X_ptr  = reinterpret_cast<const VecTpye*>(X + my_row * N);
        const VecTpye* dY_ptr = reinterpret_cast<const VecTpye*>(dY + my_row * N);
        VecTpye* dX_ptr       = reinterpret_cast<VecTpye*>(dX + my_row * N);
        VecTpye tdx;
        scalar_t* pdx = (scalar_t*)(&tdx);
        for(int j = lid; j < tcol; j += WARP)
        {
            tx     = X_ptr[j];
            tdy    = dY_ptr[j];
            tgamma = *(reinterpret_cast<const VecTpye*>(gamma + j * VEC));
#pragma unroll
            for(int i = 0; i < VEC; i++)
            {
                pdx[i] = trstd * static_cast<T_ACC>(pdy[i]) * static_cast<T_ACC>(pgamma[i]) +
                         b * static_cast<T_ACC>(px[i]);
            }
            dX_ptr[j] = tdx;
        }
    }
}

// Fused multi-row backward for small M/N: dX + dgamma in one launch.
// Each block keeps partial dgamma in LDS, then atomically accumulates to global dgamma.
template <typename scalar_t, int VEC = 4, int ROWS_PER_BLOCK = 8, int MAX_N = 512>
__global__ void __launch_bounds__(ROWS_PER_BLOCK * 64, 2)
    rmsnorm_backward_kernel_multi_row_fused(int N,
                                            const scalar_t* dY,
                                            const scalar_t* X,
                                            const scalar_t* gamma,
                                            const float* rstd,
                                            scalar_t* dX,
                                            float* dgamma_acc,
                                            int rows)
{
    constexpr int WARP  = 64;
    const int row_start = blockIdx.x * ROWS_PER_BLOCK;
    const int lid       = threadIdx.x % WARP;
    const int wid       = threadIdx.x / WARP;
    const int my_row    = row_start + wid;

    using T_ACC   = at::acc_type<scalar_t, true>;
    using VecTpye = aiter::rmsnorm_autograd::aligned_vector<scalar_t, VEC>;

    __shared__ T_ACC s_b[ROWS_PER_BLOCK];
    __shared__ T_ACC dgamma_block[MAX_N];
    const int tcol = N / VEC;

    for(int c = threadIdx.x; c < N; c += blockDim.x)
    {
        dgamma_block[c] = T_ACC(0);
    }
    __syncthreads();

    T_ACC sum1 = 0;
    VecTpye tx, tdy, tgamma;
    scalar_t* px     = (scalar_t*)(&tx);
    scalar_t* pdy    = (scalar_t*)(&tdy);
    scalar_t* pgamma = (scalar_t*)(&tgamma);

    if(my_row < rows)
    {
        const VecTpye* X_ptr  = reinterpret_cast<const VecTpye*>(X + my_row * N);
        const VecTpye* dY_ptr = reinterpret_cast<const VecTpye*>(dY + my_row * N);
        for(int j = lid; j < tcol; j += WARP)
        {
            tx     = X_ptr[j];
            tdy    = dY_ptr[j];
            tgamma = *(reinterpret_cast<const VecTpye*>(gamma + j * VEC));
#pragma unroll
            for(int i = 0; i < VEC; i++)
            {
                sum1 += static_cast<T_ACC>(pdy[i]) * static_cast<T_ACC>(px[i]) *
                        static_cast<T_ACC>(pgamma[i]);
            }
        }
        sum1 = WarpReduceSum<T_ACC, 32>(sum1);
        if(lid == 0)
        {
            float trstd = rstd[my_row];
            T_ACC s     = static_cast<T_ACC>(1) / static_cast<T_ACC>(N);
            s_b[wid]    = -sum1 * static_cast<T_ACC>(trstd) * static_cast<T_ACC>(trstd) *
                       static_cast<T_ACC>(trstd) * s;
        }
    }
    __syncthreads();

    if(my_row < rows)
    {
        T_ACC b               = s_b[wid];
        float trstd           = rstd[my_row];
        const VecTpye* X_ptr  = reinterpret_cast<const VecTpye*>(X + my_row * N);
        const VecTpye* dY_ptr = reinterpret_cast<const VecTpye*>(dY + my_row * N);
        VecTpye* dX_ptr       = reinterpret_cast<VecTpye*>(dX + my_row * N);
        VecTpye tdx;
        scalar_t* pdx = (scalar_t*)(&tdx);
        for(int j = lid; j < tcol; j += WARP)
        {
            tx     = X_ptr[j];
            tdy    = dY_ptr[j];
            tgamma = *(reinterpret_cast<const VecTpye*>(gamma + j * VEC));
#pragma unroll
            for(int i = 0; i < VEC; i++)
            {
                const int col = j * VEC + i;
                const T_ACC g_contrib =
                    static_cast<T_ACC>(pdy[i]) * static_cast<T_ACC>(px[i]) * static_cast<T_ACC>(trstd);
                pdx[i] = static_cast<T_ACC>(trstd) * static_cast<T_ACC>(pdy[i]) *
                             static_cast<T_ACC>(pgamma[i]) +
                         b * static_cast<T_ACC>(px[i]);
                atomicAdd(&dgamma_block[col], g_contrib);
            }
            dX_ptr[j] = tdx;
        }
    }
    __syncthreads();

    for(int c = threadIdx.x; c < N; c += blockDim.x)
    {
        const float val = static_cast<float>(dgamma_block[c]);
        if(val != 0.f)
        {
            atomicAdd(dgamma_acc + c, val);
        }
    }
}

template <typename scalar_t, int VEC = 4>
__global__ void __launch_bounds__(1024, 2) RMSNormBackward_kernel_vec_fast(int N,
                                                                           const scalar_t* dY,
                                                                           const scalar_t* X,
                                                                           const scalar_t* gamma,
                                                                           const float* rstd,
                                                                           scalar_t* dX)
{
    RMSNORMBACKWARD_VEC_2048
    if(j < tcol)
    {
#pragma unroll
        for(int i = 0; i < VEC; i++)
        {
            pdx[i] = trstd * static_cast<T_ACC>(pdy[i]) * static_cast<T_ACC>(pgamma[i]) +
                     b * static_cast<T_ACC>(px[i]);
        }
        *(VecTpye*)(dX + index) = tdx;
    }
}

template <typename scalar_t, int VEC = 4>
__global__ void __launch_bounds__(512, 2) RMSNormBackward_kernel_vec(int N,
                                                                     const scalar_t* dY,
                                                                     const scalar_t* X,
                                                                     const scalar_t* gamma,
                                                                     const float* rstd,
                                                                     scalar_t* dX)
{
    RMSNORMBACKWARD_VEC
    for(int off = j; off < tcol; off += blockDim.x)
    {
        const int index = i * N + off * VEC;
        tx              = *(VecTpye*)(X + index);
        tdy             = *(VecTpye*)(dY + index);
        tgamma          = *(VecTpye*)(gamma + off * VEC);
#pragma unroll
        for(int ii = 0; ii < VEC; ii++)
        {
            pdx[ii] = trstd * static_cast<T_ACC>(pdy[ii]) * static_cast<T_ACC>(pgamma[ii]) +
                      b * static_cast<T_ACC>(px[ii]);
        }
        *(VecTpye*)(dX + index) = tdx;
    }
}

template <typename scalar_t, int VEC, int ROWS_PER_BLOCK>
void launch_forward_multi_row(scalar_t* input,
                              scalar_t* ret,
                              float* rstd,
                              scalar_t* gamma,
                              int cols,
                              int rows,
                              scalar_t eps,
                              hipStream_t stream)
{
    int grid = (rows + ROWS_PER_BLOCK - 1) / ROWS_PER_BLOCK;
    rmsnorm_forward_kernel_multi_row<scalar_t, VEC, ROWS_PER_BLOCK>
        <<<grid, ROWS_PER_BLOCK * 64, 0, stream>>>(input, ret, rstd, gamma, cols, rows, eps);
}

template <typename scalar_t, int VEC, int ROWS_PER_BLOCK>
void launch_backward_multi_row(int N,
                               const scalar_t* dY,
                               const scalar_t* X,
                               const scalar_t* gamma,
                               const float* rstd,
                               scalar_t* dX,
                               int rows,
                               hipStream_t stream)
{
    int grid = (rows + ROWS_PER_BLOCK - 1) / ROWS_PER_BLOCK;
    rmsnorm_backward_kernel_multi_row<scalar_t, VEC, ROWS_PER_BLOCK>
        <<<grid, ROWS_PER_BLOCK * 64, 0, stream>>>(N, dY, X, gamma, rstd, dX, rows);
}

template <typename scalar_t, int VEC, int ROWS_PER_BLOCK>
void launch_backward_multi_row_fused(int N,
                                     const scalar_t* dY,
                                     const scalar_t* X,
                                     const scalar_t* gamma,
                                     const float* rstd,
                                     scalar_t* dX,
                                     float* dgamma_acc,
                                     int rows,
                                     hipStream_t stream)
{
    int grid = (rows + ROWS_PER_BLOCK - 1) / ROWS_PER_BLOCK;
    rmsnorm_backward_kernel_multi_row_fused<scalar_t, VEC, ROWS_PER_BLOCK, 512>
        <<<grid, ROWS_PER_BLOCK * 64, 0, stream>>>(N, dY, X, gamma, rstd, dX, dgamma_acc, rows);
}

template <typename scalar_t>
void launch_forward_multi_row_dispatch(int vec,
                                       scalar_t* input,
                                       scalar_t* ret,
                                       float* rstd,
                                       scalar_t* gamma,
                                       int cols,
                                       int rows,
                                       scalar_t eps,
                                       hipStream_t stream)
{
    const int rpb = pick_small_rows_per_block(rows);
    if(vec == 4)
    {
        if(rpb == 16)
        {
            launch_forward_multi_row<scalar_t, 4, 16>(input, ret, rstd, gamma, cols, rows, eps, stream);
        }
        else
        {
            launch_forward_multi_row<scalar_t, 4, 8>(input, ret, rstd, gamma, cols, rows, eps, stream);
        }
    }
    else if(vec == 8)
    {
        if(rpb == 16)
        {
            launch_forward_multi_row<scalar_t, 8, 16>(input, ret, rstd, gamma, cols, rows, eps, stream);
        }
        else
        {
            launch_forward_multi_row<scalar_t, 8, 8>(input, ret, rstd, gamma, cols, rows, eps, stream);
        }
    }
}

template <typename scalar_t>
void launch_backward_multi_row_dispatch(int vec,
                                        int N,
                                        const scalar_t* dY,
                                        const scalar_t* X,
                                        const scalar_t* gamma,
                                        const float* rstd,
                                        scalar_t* dX,
                                        int rows,
                                        hipStream_t stream)
{
    const int rpb = pick_small_rows_per_block(rows, 16);
    if(vec == 4)
    {
        if(rpb == 16)
        {
            launch_backward_multi_row<scalar_t, 4, 16>(N, dY, X, gamma, rstd, dX, rows, stream);
        }
        else
        {
            launch_backward_multi_row<scalar_t, 4, 8>(N, dY, X, gamma, rstd, dX, rows, stream);
        }
    }
    else if(vec == 8)
    {
        if(rpb == 16)
        {
            launch_backward_multi_row<scalar_t, 8, 16>(N, dY, X, gamma, rstd, dX, rows, stream);
        }
        else
        {
            launch_backward_multi_row<scalar_t, 8, 8>(N, dY, X, gamma, rstd, dX, rows, stream);
        }
    }
}

template <typename scalar_t>
void launch_backward_fused_dispatch(int vec,
                                    int N,
                                    const scalar_t* dY,
                                    const scalar_t* X,
                                    const scalar_t* gamma,
                                    const float* rstd,
                                    scalar_t* dX,
                                    float* dgamma_acc,
                                    int rows,
                                    hipStream_t stream)
{
    const int rpb = pick_small_rows_per_block(rows, 16);
    if(vec == 4)
    {
        if(rpb == 16)
        {
            launch_backward_multi_row_fused<scalar_t, 4, 16>(
                N, dY, X, gamma, rstd, dX, dgamma_acc, rows, stream);
        }
        else
        {
            launch_backward_multi_row_fused<scalar_t, 4, 8>(
                N, dY, X, gamma, rstd, dX, dgamma_acc, rows, stream);
        }
    }
    else if(vec == 8)
    {
        if(rpb == 16)
        {
            launch_backward_multi_row_fused<scalar_t, 8, 16>(
                N, dY, X, gamma, rstd, dX, dgamma_acc, rows, stream);
        }
        else
        {
            launch_backward_multi_row_fused<scalar_t, 8, 8>(
                N, dY, X, gamma, rstd, dX, dgamma_acc, rows, stream);
        }
    }
}

} // namespace

std::tuple<at::Tensor, at::Tensor> rmsnorm_forward_impl(const at::Tensor& self,
                                                        const at::Tensor& weight,
                                                        double ln_epsilon,
                                                        bool training)
{
    TORCH_CHECK(self.is_cuda(), "rmsnorm_forward_autograd expects a CUDA/ROCm tensor");
    TORCH_CHECK(weight.is_cuda(), "rmsnorm_forward_autograd expects weight on CUDA/ROCm");
    const int cols = self.sizes().back();
    TORCH_CHECK(cols >= 64, "rmsnorm_forward_autograd requires hidden size >= 64, got ", cols);
    const int nelem = self.numel();
    const int rows  = nelem / cols;
    at::Tensor ret  = at::empty_like(self);
    at::Tensor rstd = at::empty({0}, self.options().dtype(at::ScalarType::Float));
    if(training)
    {
        rstd = at::empty({rows}, self.options().dtype(at::ScalarType::Float));
    }

    const at::hip::OptionalHIPGuardMasqueradingAsCUDA device_guard(device_of(self));
    const hipStream_t stream = at::hip::getCurrentHIPStream();

    AT_DISPATCH_FLOATING_TYPES_AND2(
        at::ScalarType::Half,
        at::ScalarType::BFloat16,
        self.scalar_type(),
        "rmsnorm_forward_autograd",
        [&] {
            scalar_t* self_data   = self.data_ptr<scalar_t>();
            scalar_t* ret_data    = ret.data_ptr<scalar_t>();
            scalar_t* weight_data = weight.data_ptr<scalar_t>();
            scalar_t eps          = static_cast<scalar_t>(ln_epsilon);
            float* rstd_data      = training ? rstd.data_ptr<float>() : nullptr;
            if(cols % 16 == 0 && cols <= 16384)
            {
                if(cols <= 128)
                {
                    if(rows <= kSmallRowsMultiRow)
                    {
                        launch_forward_multi_row_dispatch<scalar_t>(
                            4, self_data, ret_data, rstd_data, weight_data, cols, rows, eps, stream);
                    }
                    else
                    {
                        rmsnorm_forward_kernel_fast<scalar_t, 4, 128>
                            <<<rows, 128, 0, stream>>>(
                                self_data, ret_data, rstd_data, weight_data, cols, eps);
                    }
                }
                else if(cols <= 1024)
                {
                    if(rows <= kSmallRowsMultiRow)
                    {
                        launch_forward_multi_row_dispatch<scalar_t>(
                            4, self_data, ret_data, rstd_data, weight_data, cols, rows, eps, stream);
                    }
                    else
                    {
                        rmsnorm_forward_kernel_fast<scalar_t, 4, 256>
                            <<<rows, 256, 0, stream>>>(
                                self_data, ret_data, rstd_data, weight_data, cols, eps);
                    }
                }
                else if(cols <= 2048)
                {
                    if(rows <= kSmallRowsMultiRow)
                    {
                        launch_forward_multi_row_dispatch<scalar_t>(
                            8, self_data, ret_data, rstd_data, weight_data, cols, rows, eps, stream);
                    }
                    else
                    {
                        rmsnorm_forward_kernel_fast<scalar_t, 8, 256>
                            <<<rows, 256, 0, stream>>>(
                                self_data, ret_data, rstd_data, weight_data, cols, eps);
                    }
                }
                else if(cols <= 4096)
                {
                    if(rows > 1200)
                    {
                        rmsnorm_forward_kernel_fast<scalar_t, 8, 512>
                            <<<rows, 512, 0, stream>>>(
                                self_data, ret_data, rstd_data, weight_data, cols, eps);
                    }
                    else
                    {
                        rmsnorm_forward_kernel_fast<scalar_t, 4, 1024>
                            <<<rows, 1024, 0, stream>>>(
                                self_data, ret_data, rstd_data, weight_data, cols, eps);
                    }
                }
                else if(cols <= 8192)
                {
                    rmsnorm_forward_kernel_fast<scalar_t, 8, 1024>
                        <<<rows, 1024, 0, stream>>>(
                            self_data, ret_data, rstd_data, weight_data, cols, eps);
                }
                else
                {
                    rmsnorm_forward_kernel_fast<scalar_t, 16, 1024>
                        <<<rows, 1024, 0, stream>>>(
                            self_data, ret_data, rstd_data, weight_data, cols, eps);
                }
            }
            else
            {
                rmsnorm_forward_kernel<scalar_t, 1><<<rows, get_layernorm_blocksize(cols), 0, stream>>>(
                    self_data, ret_data, rstd_data, weight_data, cols, eps);
            }
        });
    return std::tuple<at::Tensor, at::Tensor>(ret, rstd);
}

std::tuple<at::Tensor, at::Tensor> rmsnorm_backward_impl(const at::Tensor& grad,
                                                         const at::Tensor& X,
                                                         const at::Tensor& rstd,
                                                         const at::Tensor& gamma)
{
    int N      = grad.sizes().back();
    int nelem  = grad.numel();
    int M      = grad.numel() / N;
    auto pgrad = grad.expect_contiguous();
    at::Tensor dX     = at::empty_like(*pgrad);
    at::Tensor dgamma = at::empty_like(gamma);

    const at::hip::OptionalHIPGuardMasqueradingAsCUDA device_guard(device_of(grad));
    const hipStream_t stream = at::hip::getCurrentHIPStream();

    AT_DISPATCH_FLOATING_TYPES_AND2(
        at::ScalarType::Half,
        at::ScalarType::BFloat16,
        grad.scalar_type(),
        "rmsnorm_backward_autograd",
        [&] {
            scalar_t* dY_data     = pgrad->data_ptr<scalar_t>();
            scalar_t* X_data      = X.data_ptr<scalar_t>();
            float* rstd_data      = rstd.data_ptr<float>();
            scalar_t* gamma_data  = gamma.data_ptr<scalar_t>();
            scalar_t* dgamma_data = dgamma.data_ptr<scalar_t>();
            scalar_t* dX_data     = dX.data_ptr<scalar_t>();

            const bool use_fused_small_bwd = (M <= 512 && N <= 512 && (N % 16 == 0));
            at::Tensor dgamma_acc;
            if(use_fused_small_bwd)
            {
                dgamma_acc = at::zeros({N}, gamma.options().dtype(at::ScalarType::Float));
            }
            if(!use_fused_small_bwd)
            {
                Gamma_Backward<scalar_t>(nelem, N, dY_data, X_data, rstd_data, dgamma_data, stream);
            }
            if(N % 16 == 0 && N <= 16384)
            {
                if(use_fused_small_bwd)
                {
                    float* dgamma_acc_data = dgamma_acc.data_ptr<float>();
                    const int vec          = N <= 128 ? 4 : 8;
                    launch_backward_fused_dispatch<scalar_t>(
                        vec, N, dY_data, X_data, gamma_data, rstd_data, dX_data, dgamma_acc_data, M, stream);
                    dgamma.copy_(dgamma_acc);
                }
                else if(N <= 1024)
                {
                    if(M <= kSmallRowsMultiRow)
                    {
                        const int vec = N <= 128 ? 4 : 8;
                        launch_backward_multi_row_dispatch<scalar_t>(
                            vec, N, dY_data, X_data, gamma_data, rstd_data, dX_data, M, stream);
                    }
                    else
                    {
                        const int block =
                            get_vec_backward_block_size(N, 8, 128);
                        RMSNormBackward_kernel_vec_fast<scalar_t, 8>
                            <<<M, block, 0, stream>>>(N, dY_data, X_data, gamma_data, rstd_data, dX_data);
                    }
                }
                else if(N <= 2048)
                {
                    if(M <= kSmallRowsMultiRow)
                    {
                        launch_backward_multi_row_dispatch<scalar_t>(
                            8, N, dY_data, X_data, gamma_data, rstd_data, dX_data, M, stream);
                    }
                    else
                    {
                        const int block =
                            get_vec_backward_block_size(N, 8, 256);
                        RMSNormBackward_kernel_vec_fast<scalar_t, 8>
                            <<<M, block, 0, stream>>>(N, dY_data, X_data, gamma_data, rstd_data, dX_data);
                    }
                }
                else if(N <= 4096)
                {
                    if(M > 1200)
                    {
                        const int block =
                            get_vec_backward_block_size(N, 8, 512);
                        RMSNormBackward_kernel_vec_fast<scalar_t, 8>
                            <<<M, block, 0, stream>>>(N, dY_data, X_data, gamma_data, rstd_data, dX_data);
                    }
                    else
                    {
                        const int block =
                            get_vec_backward_block_size(N, 4, 1024);
                        RMSNormBackward_kernel_vec_fast<scalar_t, 4>
                            <<<M, block, 0, stream>>>(N, dY_data, X_data, gamma_data, rstd_data, dX_data);
                    }
                }
                else if(N <= 8192)
                {
                    const int block = get_vec_backward_block_size(N, 8, 1024);
                    RMSNormBackward_kernel_vec_fast<scalar_t, 8>
                        <<<M, block, 0, stream>>>(N, dY_data, X_data, gamma_data, rstd_data, dX_data);
                }
                else
                {
                    const int block = get_vec_backward_block_size(N, 16, 1024);
                    RMSNormBackward_kernel_vec_fast<scalar_t, 16>
                        <<<M, block, 0, stream>>>(N, dY_data, X_data, gamma_data, rstd_data, dX_data);
                }
            }
            else
            {
                RMSNormBackward_kernel_vec<scalar_t><<<M, 512, 0, stream>>>(
                    N, dY_data, X_data, gamma_data, rstd_data, dX_data);
            }
        });
    return std::tuple<at::Tensor, at::Tensor>(dX, dgamma);
}

} // namespace rmsnorm_autograd
} // namespace aiter

std::tuple<torch::Tensor, torch::Tensor> rmsnorm_forward_autograd(torch::Tensor& x,
                                                         torch::Tensor& weight,
                                                         double eps,
                                                         bool training)
{
    auto px      = x.contiguous();
    auto pweight = weight.contiguous();
    return aiter::rmsnorm_autograd::rmsnorm_forward_impl(px, pweight, eps, training);
}

std::tuple<torch::Tensor, torch::Tensor> rmsnorm_backward_autograd(torch::Tensor& grad,
                                                          torch::Tensor& x,
                                                          torch::Tensor& rstd,
                                                          torch::Tensor& weight)
{
    return aiter::rmsnorm_autograd::rmsnorm_backward_impl(grad, x, rstd, weight);
}
