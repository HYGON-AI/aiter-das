// SPDX-License-Identifier: MIT
// Copyright (C) 2026, Hygon Info Technologies Ltd. All rights reserved.
#pragma once

#ifdef __HIP_DEVICE_COMPILE__
#include "opus/opus.hpp"
#else
#include "opus/hip_minimal.hpp"
#endif

#ifdef __HIP_DEVICE_COMPILE__
namespace opus_gemm_hcu_pipeline {

using opus::operator""_I;

struct bf16_opus_traits
{
    static constexpr int BLOCK_SIZE = 256;
    static constexpr int B_M        = 64;
    static constexpr int B_N        = 64;
    static constexpr int B_K        = 32;
    static constexpr int LDS_K      = 40;
    static constexpr int VEC_A      = 8;
    static constexpr int VEC_B      = 8;
    static constexpr int MMA_VEC_A  = 4;
    static constexpr int MMA_VEC_B  = 4;
    static constexpr int VEC_C      = 1;
    static constexpr int T_M        = 2;
    static constexpr int T_N        = 2;
    static constexpr int T_K        = 1;
    static constexpr int E_M        = 2;
    static constexpr int E_N        = 2;
    static constexpr int E_K        = 2;
    static constexpr int W_M        = 16;
    static constexpr int W_N        = 16;
    static constexpr int W_K        = 16;
};

// One 128-bit transaction per thread covers a complete 64x32 operand tile.
// The same logical layout is used for global and LDS coordinates; only the
// leading stride changes.  This is deliberately expressed as an Opus layout
// instead of open-coded scalar indexing.
template<int VEC>
OPUS_D auto make_stage_layout(int row, int k_vec, int leading_stride)
{
    using T = bf16_opus_traits;
    return opus::make_layout<VEC>(
        opus::make_tuple(opus::number<T::B_M>{},
                         opus::number<T::B_K / VEC>{},
                         opus::number<VEC>{}),
        opus::make_tuple(leading_stride, opus::number<VEC>{}, 1_I),
        opus::make_tuple(row, k_vec, opus::underscore{}));
}

} // namespace opus_gemm_hcu_pipeline
#endif

// One wave computes one 16x16 C tile.  The basic HCU BF16 MMAC lane mapping
// is shared by gfx936, gfx938 and gfx946:
//   A/B: lane % 16 selects M/N, lane / 16 selects one four-element K group.
//   C[s]: m = lane % 16, n = s * 4 + lane / 16, s in [0, 4).
extern "C" __global__ __launch_bounds__(64)
void opus_gemm_a16w16_hcu_kernel(const void* a_ptr,
                                 const void* b_ptr,
                                 void* c_ptr,
                                 const void* bias_ptr,
                                 float* workspace_ptr,
                                 int batch,
                                 int m_size,
                                 int n_size,
                                 int k_size,
                                 long long stride_a_batch,
                                 long long stride_b_batch,
                                 long long stride_c_batch,
                                 int split_k,
                                 int bias_stride_batch,
                                 bool bias_fp32,
                                 bool output_fp32)
#ifdef __HIP_DEVICE_COMPILE__
{
#if defined(__gfx936__) || defined(__gfx938__) || defined(__gfx946__)
    const int lane = opus::thread_id_x();
    const int batch_split_id = opus::block_id_z();
    const int batch_id = batch_split_id / split_k;
    const int split_id = batch_split_id - batch_id * split_k;
    const int m = opus::block_id_y() * 16 + lane % 16;
    const int b_n = opus::block_id_x() * 16 + lane % 16;
    const int k_lane = (lane / 16) * 4;

    const auto* a = reinterpret_cast<const opus::bf16_t*>(a_ptr) +
                    static_cast<long long>(batch_id) * stride_a_batch;
    const auto* b = reinterpret_cast<const opus::bf16_t*>(b_ptr) +
                    static_cast<long long>(batch_id) * stride_b_batch;
    opus::fp32x4_t acc{0.0f, 0.0f, 0.0f, 0.0f};

    const int total_k_tiles = (k_size + 15) / 16;
    const int tiles_per_split = (total_k_tiles + split_k - 1) / split_k;
    const int tile_begin = split_id * tiles_per_split;
    const int tile_end = tile_begin + tiles_per_split < total_k_tiles
                             ? tile_begin + tiles_per_split
                             : total_k_tiles;

    for(int tile = tile_begin; tile < tile_end; ++tile)
    {
        const int k0 = tile * 16;
        opus::bf16x4_t a_vec{};
        opus::bf16x4_t b_vec{};
#pragma unroll
        for(int i = 0; i < 4; ++i)
        {
            const int k = k0 + k_lane + i;
            if(m < m_size && k < k_size)
                a_vec[i] = a[static_cast<long long>(m) * k_size + k];
            if(b_n < n_size && k < k_size)
                b_vec[i] = b[static_cast<long long>(b_n) * k_size + k];
        }
        acc = __builtin_hcu_mmac_f32_16x16x16_bf16(a_vec, b_vec, acc);
    }

    const int c_n_group = lane / 16;
#pragma unroll
    for(int s = 0; s < 4; ++s)
    {
        const int n = opus::block_id_x() * 16 + s * 4 + c_n_group;
        if(m < m_size && n < n_size)
        {
            const long long c_offset = static_cast<long long>(batch_id) * stride_c_batch +
                                       static_cast<long long>(m) * n_size + n;
            if(split_k > 1)
            {
                const long long workspace_offset =
                    (static_cast<long long>(split_id) * batch + batch_id) * m_size * n_size +
                    static_cast<long long>(m) * n_size + n;
                workspace_ptr[workspace_offset] = acc[s];
            }
            else
            {
                float value = acc[s];
                if(bias_stride_batch >= 0)
                {
                    const long long bias_offset =
                        static_cast<long long>(batch_id) * bias_stride_batch + n;
                    value += bias_fp32
                                 ? reinterpret_cast<const opus::fp32_t*>(bias_ptr)[bias_offset]
                                 : opus::bf16_to_fp32(
                                       reinterpret_cast<const opus::bf16_t*>(bias_ptr)[bias_offset]);
                }
                if(output_fp32)
                    reinterpret_cast<opus::fp32_t*>(c_ptr)[c_offset] = value;
                else
                    reinterpret_cast<opus::bf16_t*>(c_ptr)[c_offset] =
                        opus::fp32_to_bf16(value);
            }
        }
    }
#else
    (void)a_ptr;
    (void)b_ptr;
    (void)c_ptr;
    (void)bias_ptr;
    (void)workspace_ptr;
    (void)batch;
    (void)m_size;
    (void)n_size;
    (void)k_size;
    (void)stride_a_batch;
    (void)stride_b_batch;
    (void)stride_c_batch;
    (void)split_k;
    (void)bias_stride_batch;
    (void)bias_fp32;
    (void)output_fp32;
#endif
}
#else
{
    // The host pass needs a definition (not only a declaration) so hipcc/aicc
    // emits the __device_stub__ used by hipLaunchKernelGGL. Device work lives
    // exclusively in the branch above.
    (void)a_ptr;
    (void)b_ptr;
    (void)c_ptr;
    (void)bias_ptr;
    (void)workspace_ptr;
    (void)batch;
    (void)m_size;
    (void)n_size;
    (void)k_size;
    (void)stride_a_batch;
    (void)stride_b_batch;
    (void)stride_c_batch;
    (void)split_k;
    (void)bias_stride_batch;
    (void)bias_fp32;
    (void)output_fp32;
}
#endif

extern "C" __global__ __launch_bounds__(64)
void opus_gemm_a16w16_hcu_lds_kernel(const void* a_ptr,
                                     const void* b_ptr,
                                     void* c_ptr,
                                     const void* bias_ptr,
                                     float* workspace_ptr,
                                     int batch,
                                     int m_size,
                                     int n_size,
                                     int k_size,
                                     long long stride_a_batch,
                                     long long stride_b_batch,
                                     long long stride_c_batch,
                                     int split_k,
                                     int bias_stride_batch,
                                     bool bias_fp32,
                                     bool output_fp32)
#ifdef __HIP_DEVICE_COMPILE__
{
#if defined(__gfx936__) || defined(__gfx938__) || defined(__gfx946__)
    constexpr int lds_stride = 18;
    __shared__ opus::bf16_t smem_a[16 * lds_stride];
    __shared__ opus::bf16_t smem_b[16 * lds_stride];

    const int lane = opus::thread_id_x();
    const int batch_split_id = opus::block_id_z();
    const int batch_id = batch_split_id / split_k;
    const int split_id = batch_split_id - batch_id * split_k;
    const int block_m = opus::block_id_y() * 16;
    const int block_n = opus::block_id_x() * 16;
    const int m = block_m + lane % 16;
    const int b_n = block_n + lane % 16;
    const int k_lane = (lane / 16) * 4;

    const auto* a = reinterpret_cast<const opus::bf16_t*>(a_ptr) +
                    static_cast<long long>(batch_id) * stride_a_batch;
    const auto* b = reinterpret_cast<const opus::bf16_t*>(b_ptr) +
                    static_cast<long long>(batch_id) * stride_b_batch;
    opus::fp32x4_t acc{0.0f, 0.0f, 0.0f, 0.0f};

    const int total_k_tiles = (k_size + 15) / 16;
    const int tiles_per_split = (total_k_tiles + split_k - 1) / split_k;
    const int tile_begin = split_id * tiles_per_split;
    const int tile_end = tile_begin + tiles_per_split < total_k_tiles
                             ? tile_begin + tiles_per_split
                             : total_k_tiles;

    for(int tile = tile_begin; tile < tile_end; ++tile)
    {
        const int k0 = tile * 16;
#pragma unroll
        for(int i = 0; i < 4; ++i)
        {
            const int linear = lane * 4 + i;
            const int tile_row = linear / 16;
            const int tile_k = linear - tile_row * 16;
            const int global_k = k0 + tile_k;
            const int global_m = block_m + tile_row;
            const int global_n = block_n + tile_row;
            opus::bf16_t a_value{};
            opus::bf16_t b_value{};
            if(global_m < m_size && global_k < k_size)
                a_value = a[static_cast<long long>(global_m) * k_size + global_k];
            if(global_n < n_size && global_k < k_size)
                b_value = b[static_cast<long long>(global_n) * k_size + global_k];
            smem_a[tile_row * lds_stride + tile_k] = a_value;
            smem_b[tile_row * lds_stride + tile_k] = b_value;
        }
        __syncthreads();

        opus::bf16x4_t a_vec{};
        opus::bf16x4_t b_vec{};
#pragma unroll
        for(int i = 0; i < 4; ++i)
        {
            a_vec[i] = smem_a[(lane % 16) * lds_stride + k_lane + i];
            b_vec[i] = smem_b[(lane % 16) * lds_stride + k_lane + i];
        }
        acc = __builtin_hcu_mmac_f32_16x16x16_bf16(a_vec, b_vec, acc);
        __syncthreads();
    }

    const int c_n_group = lane / 16;
#pragma unroll
    for(int s = 0; s < 4; ++s)
    {
        const int n = block_n + s * 4 + c_n_group;
        if(m < m_size && n < n_size)
        {
            const long long c_offset = static_cast<long long>(batch_id) * stride_c_batch +
                                       static_cast<long long>(m) * n_size + n;
            if(split_k > 1)
            {
                const long long workspace_offset =
                    (static_cast<long long>(split_id) * batch + batch_id) * m_size * n_size +
                    static_cast<long long>(m) * n_size + n;
                workspace_ptr[workspace_offset] = acc[s];
            }
            else
            {
                float value = acc[s];
                if(bias_stride_batch >= 0)
                {
                    const long long bias_offset =
                        static_cast<long long>(batch_id) * bias_stride_batch + n;
                    value += bias_fp32
                                 ? reinterpret_cast<const opus::fp32_t*>(bias_ptr)[bias_offset]
                                 : opus::bf16_to_fp32(
                                       reinterpret_cast<const opus::bf16_t*>(bias_ptr)[bias_offset]);
                }
                if(output_fp32)
                    reinterpret_cast<opus::fp32_t*>(c_ptr)[c_offset] = value;
                else
                    reinterpret_cast<opus::bf16_t*>(c_ptr)[c_offset] =
                        opus::fp32_to_bf16(value);
            }
        }
    }
#else
    (void)a_ptr;
    (void)b_ptr;
    (void)c_ptr;
    (void)bias_ptr;
    (void)workspace_ptr;
    (void)batch;
    (void)m_size;
    (void)n_size;
    (void)k_size;
    (void)stride_a_batch;
    (void)stride_b_batch;
    (void)stride_c_batch;
    (void)split_k;
    (void)bias_stride_batch;
    (void)bias_fp32;
    (void)output_fp32;
#endif
}
#else
{
    (void)a_ptr;
    (void)b_ptr;
    (void)c_ptr;
    (void)bias_ptr;
    (void)workspace_ptr;
    (void)batch;
    (void)m_size;
    (void)n_size;
    (void)k_size;
    (void)stride_a_batch;
    (void)stride_b_batch;
    (void)stride_c_batch;
    (void)split_k;
    (void)bias_stride_batch;
    (void)bias_fp32;
    (void)output_fp32;
}
#endif

// Four waves cooperate on one 32x32 output tile.  A 32x16 A tile and a
// 32x16 B tile are loaded once, then reused by two wave rows/columns.
extern "C" __global__ __launch_bounds__(256)
void opus_gemm_a16w16_hcu_lds_32x32_kernel(const void* a_ptr,
                                           const void* b_ptr,
                                           void* c_ptr,
                                           const void* bias_ptr,
                                           float* workspace_ptr,
                                           int batch,
                                           int m_size,
                                           int n_size,
                                           int k_size,
                                           long long stride_a_batch,
                                           long long stride_b_batch,
                                           long long stride_c_batch,
                                           int split_k,
                                           int bias_stride_batch,
                                           bool bias_fp32,
                                           bool output_fp32)
#ifdef __HIP_DEVICE_COMPILE__
{
#if defined(__gfx936__) || defined(__gfx938__) || defined(__gfx946__)
    constexpr int lds_stride = 18;
    __shared__ opus::bf16_t smem_a[32 * lds_stride];
    __shared__ opus::bf16_t smem_b[32 * lds_stride];

    const int tid = opus::thread_id_x();
    const int wave_id = tid / 64;
    const int lane = tid - wave_id * 64;
    const int wave_m = wave_id / 2;
    const int wave_n = wave_id - wave_m * 2;
    const int batch_split_id = opus::block_id_z();
    const int batch_id = batch_split_id / split_k;
    const int split_id = batch_split_id - batch_id * split_k;
    const int block_m = opus::block_id_y() * 32;
    const int block_n = opus::block_id_x() * 32;
    const int m = block_m + wave_m * 16 + lane % 16;
    const int b_n = block_n + wave_n * 16 + lane % 16;
    const int k_lane = (lane / 16) * 4;

    const auto* a = reinterpret_cast<const opus::bf16_t*>(a_ptr) +
                    static_cast<long long>(batch_id) * stride_a_batch;
    const auto* b = reinterpret_cast<const opus::bf16_t*>(b_ptr) +
                    static_cast<long long>(batch_id) * stride_b_batch;
    opus::fp32x4_t acc{0.0f, 0.0f, 0.0f, 0.0f};

    const int total_k_tiles = (k_size + 15) / 16;
    const int tiles_per_split = (total_k_tiles + split_k - 1) / split_k;
    const int tile_begin = split_id * tiles_per_split;
    const int tile_end = tile_begin + tiles_per_split < total_k_tiles
                             ? tile_begin + tiles_per_split
                             : total_k_tiles;

    for(int tile = tile_begin; tile < tile_end; ++tile)
    {
        const int k0 = tile * 16;
#pragma unroll
        for(int i = 0; i < 2; ++i)
        {
            const int linear = tid + i * 256;
            const int tile_row = linear / 16;
            const int tile_k = linear - tile_row * 16;
            const int global_k = k0 + tile_k;
            const int global_m = block_m + tile_row;
            const int global_n = block_n + tile_row;
            opus::bf16_t a_value{};
            opus::bf16_t b_value{};
            if(global_m < m_size && global_k < k_size)
                a_value = a[static_cast<long long>(global_m) * k_size + global_k];
            if(global_n < n_size && global_k < k_size)
                b_value = b[static_cast<long long>(global_n) * k_size + global_k];
            smem_a[tile_row * lds_stride + tile_k] = a_value;
            smem_b[tile_row * lds_stride + tile_k] = b_value;
        }
        __syncthreads();

        opus::bf16x4_t a_vec{};
        opus::bf16x4_t b_vec{};
#pragma unroll
        for(int i = 0; i < 4; ++i)
        {
            a_vec[i] = smem_a[(wave_m * 16 + lane % 16) * lds_stride + k_lane + i];
            b_vec[i] = smem_b[(wave_n * 16 + lane % 16) * lds_stride + k_lane + i];
        }
        acc = __builtin_hcu_mmac_f32_16x16x16_bf16(a_vec, b_vec, acc);
        __syncthreads();
    }

    const int c_n_group = lane / 16;
#pragma unroll
    for(int s = 0; s < 4; ++s)
    {
        const int n = block_n + wave_n * 16 + s * 4 + c_n_group;
        if(m < m_size && n < n_size)
        {
            const long long c_offset = static_cast<long long>(batch_id) * stride_c_batch +
                                       static_cast<long long>(m) * n_size + n;
            if(split_k > 1)
            {
                const long long workspace_offset =
                    (static_cast<long long>(split_id) * batch + batch_id) * m_size * n_size +
                    static_cast<long long>(m) * n_size + n;
                workspace_ptr[workspace_offset] = acc[s];
            }
            else
            {
                float value = acc[s];
                if(bias_stride_batch >= 0)
                {
                    const long long bias_offset =
                        static_cast<long long>(batch_id) * bias_stride_batch + n;
                    value += bias_fp32
                                 ? reinterpret_cast<const opus::fp32_t*>(bias_ptr)[bias_offset]
                                 : opus::bf16_to_fp32(
                                       reinterpret_cast<const opus::bf16_t*>(bias_ptr)[bias_offset]);
                }
                if(output_fp32)
                    reinterpret_cast<opus::fp32_t*>(c_ptr)[c_offset] = value;
                else
                    reinterpret_cast<opus::bf16_t*>(c_ptr)[c_offset] =
                        opus::fp32_to_bf16(value);
            }
        }
    }
#else
    (void)a_ptr;
    (void)b_ptr;
    (void)c_ptr;
    (void)bias_ptr;
    (void)workspace_ptr;
    (void)batch;
    (void)m_size;
    (void)n_size;
    (void)k_size;
    (void)stride_a_batch;
    (void)stride_b_batch;
    (void)stride_c_batch;
    (void)split_k;
    (void)bias_stride_batch;
    (void)bias_fp32;
    (void)output_fp32;
#endif
}
#else
{
    (void)a_ptr;
    (void)b_ptr;
    (void)c_ptr;
    (void)bias_ptr;
    (void)workspace_ptr;
    (void)batch;
    (void)m_size;
    (void)n_size;
    (void)k_size;
    (void)stride_a_batch;
    (void)stride_b_batch;
    (void)stride_c_batch;
    (void)split_k;
    (void)bias_stride_batch;
    (void)bias_fp32;
    (void)output_fp32;
}
#endif

// Opus layout-driven 4-wave pipeline.  Each workgroup computes a 64x64 tile
// and advances through K in 32-element tiles.  Global loads are prefetched to
// VGPRs while the current LDS tile is consumed, then committed to the alternate
// LDS slot.  kernelId=3 selects this path; the older kernels remain fallbacks.
extern "C" __global__ __launch_bounds__(256, 2)
void opus_gemm_a16w16_hcu_opus_64x64x32_kernel(const void* a_ptr,
                                                const void* b_ptr,
                                                void* c_ptr,
                                                const void* bias_ptr,
                                                float* workspace_ptr,
                                                int batch,
                                                int m_size,
                                                int n_size,
                                                int k_size,
                                                long long stride_a_batch,
                                                long long stride_b_batch,
                                                long long stride_c_batch,
                                                int split_k,
                                                int bias_stride_batch,
                                                bool bias_fp32,
                                                bool output_fp32)
#ifdef __HIP_DEVICE_COMPILE__
{
#if defined(__gfx936__) || defined(__gfx938__) || defined(__gfx946__)
    using namespace opus;
    using T = opus_gemm_hcu_pipeline::bf16_opus_traits;

    const int tid       = thread_id_x();
    const int wave_id   = tid / get_warp_size();
    const int lane_id   = tid % get_warp_size();
    const int wave_id_m = wave_id / T::T_N;
    const int wave_id_n = wave_id % T::T_N;

    const int batch_split_id = block_id_z();
    const int batch_id       = batch_split_id / split_k;
    const int split_id       = batch_split_id - batch_id * split_k;
    const int row            = block_id_y() * T::B_M;
    const int col            = block_id_x() * T::B_N;

    const int total_tiles    = k_size / T::B_K;
    const int tiles_per_split = (total_tiles + split_k - 1) / split_k;
    const int tile_begin     = split_id * tiles_per_split;
    const int tile_end       = min(tile_begin + tiles_per_split, total_tiles);
    const int loops          = tile_end - tile_begin;

    const auto* a_batch = reinterpret_cast<const bf16_t*>(a_ptr) +
                          static_cast<long long>(batch_id) * stride_a_batch;
    const auto* b_batch = reinterpret_cast<const bf16_t*>(b_ptr) +
                          static_cast<long long>(batch_id) * stride_b_batch;
    auto g_a = make_gmem(a_batch + static_cast<long long>(row) * k_size +
                             tile_begin * T::B_K);
    auto g_b = make_gmem(b_batch + static_cast<long long>(col) * k_size +
                             tile_begin * T::B_K);

    const int load_row = tid / (T::B_K / T::VEC_A);
    const int load_kv  = tid % (T::B_K / T::VEC_A);
    auto u_ga = opus_gemm_hcu_pipeline::make_stage_layout<T::VEC_A>(
        load_row, load_kv, k_size);
    auto u_gb = opus_gemm_hcu_pipeline::make_stage_layout<T::VEC_B>(
        load_row, load_kv, k_size);
    auto u_sa = opus_gemm_hcu_pipeline::make_stage_layout<T::VEC_A>(
        load_row, load_kv, T::LDS_K);
    auto u_sb = opus_gemm_hcu_pipeline::make_stage_layout<T::VEC_B>(
        load_row, load_kv, T::LDS_K);

    __shared__ bf16_t smem_a_storage[2][T::B_M * T::LDS_K];
    __shared__ bf16_t smem_b_storage[2][T::B_N * T::LDS_K];
    smem<bf16_t> s_a[2] = {make_smem(&smem_a_storage[0][0]),
                            make_smem(&smem_a_storage[1][0])};
    smem<bf16_t> s_b[2] = {make_smem(&smem_b_storage[0][0]),
                            make_smem(&smem_b_storage[1][0])};

    auto mma = make_tiled_mma<bf16_t, bf16_t, fp32_t>(
        seq<T::E_M, T::E_N, T::E_K>{},
        seq<T::T_M, T::T_N, T::T_K>{},
        seq<T::W_M, T::W_N, T::W_K>{},
        mmac_adaptor_hcu{});

    auto p_coord_a = opus::make_tuple(wave_id_m, lane_id % mma.grpm_a,
                                      0, lane_id / mma.grpm_a);
    auto p_coord_b = opus::make_tuple(wave_id_n, lane_id % mma.grpn_b,
                                      0, lane_id / mma.grpn_b);
    auto u_ra = partition_layout_a<T::MMA_VEC_A>(
        mma, opus::make_tuple(T::LDS_K, 1_I), p_coord_a);
    auto u_rb = partition_layout_b<T::MMA_VEC_B>(
        mma, opus::make_tuple(T::LDS_K, 1_I), p_coord_b);

    typename decltype(mma)::vtype_c v_c{0};

    auto init_a = load<T::VEC_A>(g_a, u_ga, 0);
    auto init_b = load<T::VEC_B>(g_b, u_gb, 0);
    s_waitcnt_vmcnt(0_I);
    store<T::VEC_A>(s_a[0], init_a, u_sa);
    store<T::VEC_B>(s_b[0], init_b, u_sb);
    s_waitcnt_lgkmcnt(0_I);
    __builtin_amdgcn_s_barrier();

    int current = 0;
    for(int tile = 0; tile < loops; ++tile)
    {
        auto v_a = load<T::MMA_VEC_A>(s_a[current], u_ra);
        auto v_b = load<T::MMA_VEC_B>(s_b[current], u_rb);
        s_waitcnt_lgkmcnt(0_I);

        if(tile + 1 < loops)
        {
            const int next = current ^ 1;
            auto pf_a = load<T::VEC_A>(g_a, u_ga, (tile + 1) * T::B_K);
            auto pf_b = load<T::VEC_B>(g_b, u_gb, (tile + 1) * T::B_K);
            v_c = mma(v_a, v_b, v_c);
            s_waitcnt_vmcnt(0_I);
            store<T::VEC_A>(s_a[next], pf_a, u_sa);
            store<T::VEC_B>(s_b[next], pf_b, u_sb);
            s_waitcnt_lgkmcnt(0_I);
            __builtin_amdgcn_s_barrier();
            current = next;
        }
        else
        {
            v_c = mma(v_a, v_b, v_c);
        }
    }

    auto p_coord_c = opus::make_tuple(wave_id_m, lane_id % mma.grpn_c,
                                      wave_id_n, lane_id / mma.grpn_c);
    auto u_gc = partition_layout_c<T::VEC_C>(
        mma, opus::make_tuple(n_size, 1_I), p_coord_c);

    if(split_k > 1)
    {
        const long long ws_base =
            (static_cast<long long>(split_id) * batch + batch_id) * m_size * n_size +
            static_cast<long long>(row) * n_size + col;
        auto g_ws = make_gmem(workspace_ptr + ws_base);
        store<T::VEC_C>(g_ws, v_c, u_gc);
    }
    else
    {
        if(bias_stride_batch >= 0)
        {
            auto u_gc_n = partition_layout_c<T::VEC_C>(
                mma, opus::make_tuple(0_I, 1_I), p_coord_c);
            auto n_offsets = layout_to_offsets<T::VEC_C>(u_gc_n);
            using LT = layout_load_traits<decltype(u_gc_n), T::VEC_C>;
            const long long bias_base =
                static_cast<long long>(batch_id) * bias_stride_batch + col;
            static_for<LT::r_elem.value>([&](auto i) {
                static_for<T::VEC_C>([&](auto j) {
                    const long long bias_offset = bias_base + n_offsets[i] + j.value;
                    const float b = bias_fp32
                                        ? reinterpret_cast<const fp32_t*>(bias_ptr)[bias_offset]
                                        : bf16_to_fp32(
                                              reinterpret_cast<const bf16_t*>(bias_ptr)[bias_offset]);
                    v_c[i.value * T::VEC_C + j.value] += b;
                });
            });
        }

        const long long c_base = static_cast<long long>(batch_id) * stride_c_batch +
                                 static_cast<long long>(row) * n_size + col;
        if(output_fp32)
        {
            auto g_c = make_gmem(reinterpret_cast<fp32_t*>(c_ptr) + c_base);
            store<T::VEC_C>(g_c, v_c, u_gc);
        }
        else
        {
            auto g_c = make_gmem(reinterpret_cast<bf16_t*>(c_ptr) + c_base);
            auto v_out = cast<bf16_t>(v_c);
            store<T::VEC_C>(g_c, v_out, u_gc);
        }
    }
#else
    (void)a_ptr; (void)b_ptr; (void)c_ptr; (void)bias_ptr; (void)workspace_ptr;
    (void)batch; (void)m_size; (void)n_size; (void)k_size;
    (void)stride_a_batch; (void)stride_b_batch; (void)stride_c_batch;
    (void)split_k; (void)bias_stride_batch; (void)bias_fp32; (void)output_fp32;
#endif
}
#else
{
    (void)a_ptr; (void)b_ptr; (void)c_ptr; (void)bias_ptr; (void)workspace_ptr;
    (void)batch; (void)m_size; (void)n_size; (void)k_size;
    (void)stride_a_batch; (void)stride_b_batch; (void)stride_c_batch;
    (void)split_k; (void)bias_stride_batch; (void)bias_fp32; (void)output_fp32;
}
#endif

extern "C" __global__ __launch_bounds__(256)
void opus_gemm_a16w16_splitk_reduce_hcu_kernel(const float* workspace_ptr,
                                               const void* bias_ptr,
                                               void* c_ptr,
                                               int batch,
                                               int m_size,
                                               int n_size,
                                               int split_k,
                                               long long stride_c_batch,
                                               int bias_stride_batch,
                                               bool bias_fp32,
                                               bool output_fp32)
#ifdef __HIP_DEVICE_COMPILE__
{
#if defined(__gfx936__) || defined(__gfx938__) || defined(__gfx946__)
    const long long index = static_cast<long long>(opus::block_id_x()) * 256 +
                            opus::thread_id_x();
    const long long matrix_elements = static_cast<long long>(batch) * m_size * n_size;
    if(index < matrix_elements)
    {
        float value = 0.0f;
        for(int split_id = 0; split_id < split_k; ++split_id)
            value += workspace_ptr[static_cast<long long>(split_id) * matrix_elements + index];

        const int n = static_cast<int>(index % n_size);
        const int batch_id = static_cast<int>(index / (static_cast<long long>(m_size) * n_size));
        if(bias_stride_batch >= 0)
        {
            const long long bias_offset =
                static_cast<long long>(batch_id) * bias_stride_batch + n;
            value += bias_fp32
                         ? reinterpret_cast<const opus::fp32_t*>(bias_ptr)[bias_offset]
                         : opus::bf16_to_fp32(
                               reinterpret_cast<const opus::bf16_t*>(bias_ptr)[bias_offset]);
        }

        const long long mn = index % (static_cast<long long>(m_size) * n_size);
        const long long c_offset = static_cast<long long>(batch_id) * stride_c_batch + mn;
        if(output_fp32)
            reinterpret_cast<opus::fp32_t*>(c_ptr)[c_offset] = value;
        else
            reinterpret_cast<opus::bf16_t*>(c_ptr)[c_offset] = opus::fp32_to_bf16(value);
    }
#else
    (void)workspace_ptr;
    (void)bias_ptr;
    (void)c_ptr;
    (void)batch;
    (void)m_size;
    (void)n_size;
    (void)split_k;
    (void)stride_c_batch;
    (void)bias_stride_batch;
    (void)bias_fp32;
    (void)output_fp32;
#endif
}
#else
{
    (void)workspace_ptr;
    (void)bias_ptr;
    (void)c_ptr;
    (void)batch;
    (void)m_size;
    (void)n_size;
    (void)split_k;
    (void)stride_c_batch;
    (void)bias_stride_batch;
    (void)bias_fp32;
    (void)output_fp32;
}
#endif
