// SPDX-License-Identifier: MIT

#include <ATen/hip/HIPContext.h>
#include <ATen/hip/impl/HIPGuardImplMasqueradingAsCUDA.h>
#include <torch/extension.h>

#include <climits>
#include <cmath>
#include <cstdint>
#include <type_traits>

#include "dispatch_utils.h"
#include "hip/hip_bf16.h"
#include "hip/hip_fp16.h"
#include "hip_compat.h"

namespace aiter {

// gfx936-class: warpSize=64, up to 256 VGPR/thread, 64KB LDS/SM.
constexpr int kWarpSize = WARP_SIZE;

template <typename scalar_t>
using native_t = typename std::conditional_t<
    std::is_same_v<scalar_t, c10::Half>, __half,
    typename std::conditional_t<std::is_same_v<scalar_t, c10::BFloat16>,
                                __hip_bfloat16, scalar_t>>;

template <typename T>
static __device__ inline T b32_to_b16(float f) {
  if constexpr (std::is_same_v<T, __hip_bfloat16>) {
#if defined(__gfx936__) || defined(__gfx928__) || defined(__gfx92a__)
    return __float2bfloat16(f);
#elif defined(__gfx938__)
    __builtin_amdgcn_sched_barrier(0);
    __hip_bfloat16 res;
    asm volatile("v_cvt_bf16_f32  %0, %1 \n\t" : "=v"(res) : "v"(f));
    __builtin_amdgcn_sched_barrier(0);
    return res;
#else
    return __float2bfloat16(f);
#endif
  } else if constexpr (std::is_same_v<T, __half>) {
    return __float2half(f);
  } else {
    static_assert(std::is_same_v<T, __half> || std::is_same_v<T, __hip_bfloat16>,
                  "b32_to_b16 only supports fp16/bf16");
  }
}

constexpr float kLog2e = 1.44269504088896340736f;

// sigmoid(x) = rcp(1 + exp2(-x * log2(e))); cheaper than expf on gfx936 VALU.
__device__ __forceinline__ float swiglu_fast_sigmoid(float x) {
#if defined(__HIPCC__) || defined(__CUDA_ARCH__)
  return __builtin_amdgcn_rcpf(
      1.0f + __builtin_amdgcn_exp2f(-x * kLog2e));
#else
  return 1.0f / (1.0f + expf(-x));
#endif
}

__device__ __forceinline__ float swiglu_fast_silu(float x) {
  return x * swiglu_fast_sigmoid(x);
}

__device__ __forceinline__ float swiglu_clamp_gate(float gate_f, float limit) {
  return fminf(gate_f, limit);
}

__device__ __forceinline__ float swiglu_clamp_up(float up_f, float limit) {
  return fminf(fmaxf(up_f, -limit), limit);
}

// Wide global load/store for coalesced D-tile access (gfx936 warpSize=64).
template <int kBytes, bool NT>
__device__ __forceinline__ void swiglu_gmem_load(void* dst, const void* src) {
  if constexpr (kBytes == 4) {
    auto* d = reinterpret_cast<uint32_t*>(dst);
    auto* s = reinterpret_cast<const uint32_t*>(src);
    *d = NT ? __builtin_nontemporal_load(s) : *s;
  } else if constexpr (kBytes == 8) {
    auto* d = reinterpret_cast<uint64_t*>(dst);
    auto* s = reinterpret_cast<const uint64_t*>(src);
    *d = NT ? __builtin_nontemporal_load(s) : *s;
  } else if constexpr (kBytes == 16) {
    auto* d = reinterpret_cast<uint64_t*>(dst);
    auto* s = reinterpret_cast<const uint64_t*>(src);
    if constexpr (NT) {
      d[0] = __builtin_nontemporal_load(s);
      d[1] = __builtin_nontemporal_load(s + 1);
    } else {
      d[0] = s[0];
      d[1] = s[1];
    }
  }
}

template <int kBytes, bool NT>
__device__ __forceinline__ void swiglu_gmem_store(void* dst, const void* src) {
  if constexpr (kBytes == 4) {
    auto* d = reinterpret_cast<uint32_t*>(dst);
    auto* s = reinterpret_cast<const uint32_t*>(src);
    if constexpr (NT) {
      __builtin_nontemporal_store(*s, d);
    } else {
      *d = *s;
    }
  } else if constexpr (kBytes == 8) {
    auto* d = reinterpret_cast<uint64_t*>(dst);
    auto* s = reinterpret_cast<const uint64_t*>(src);
    if constexpr (NT) {
      __builtin_nontemporal_store(*s, d);
    } else {
      *d = *s;
    }
  } else if constexpr (kBytes == 16) {
    auto* d = reinterpret_cast<uint64_t*>(dst);
    auto* s = reinterpret_cast<const uint64_t*>(src);
    if constexpr (NT) {
      __builtin_nontemporal_store(s[0], d);
      __builtin_nontemporal_store(s[1], d + 1);
    } else {
      d[0] = s[0];
      d[1] = s[1];
    }
  }
}

template <int kDwords, bool NT>
__device__ __forceinline__ void swiglu_load_gate_up(
    uint32_t* gate_buf, uint32_t* up_buf,
    const uint32_t* gate_dw, const uint32_t* up_dw) {
  if constexpr (kDwords == 1) {
    swiglu_gmem_load<4, NT>(gate_buf, gate_dw);
    swiglu_gmem_load<4, NT>(up_buf, up_dw);
  } else if constexpr (kDwords == 2) {
    swiglu_gmem_load<8, NT>(gate_buf, gate_dw);
    swiglu_gmem_load<8, NT>(up_buf, up_dw);
  } else if constexpr (kDwords == 4) {
    swiglu_gmem_load<16, NT>(gate_buf, gate_dw);
    swiglu_gmem_load<16, NT>(up_buf, up_dw);
  } else {
#pragma unroll
    for (int d = 0; d < kDwords; ++d) {
      swiglu_gmem_load<4, NT>(&gate_buf[d], &gate_dw[d]);
      swiglu_gmem_load<4, NT>(&up_buf[d], &up_dw[d]);
    }
  }
}

template <int kDwords>
__device__ __forceinline__ void swiglu_store_out(
    uint32_t* out_dw, const uint32_t* out_vals) {
  // Regular stores: HCU L2 handles write-once output better than NT on gfx936.
  if constexpr (kDwords == 1) {
    swiglu_gmem_store<4, false>(out_dw, out_vals);
  } else if constexpr (kDwords == 2) {
    swiglu_gmem_store<8, false>(out_dw, out_vals);
  } else if constexpr (kDwords == 4) {
    swiglu_gmem_store<16, false>(out_dw, out_vals);
  } else {
#pragma unroll
    for (int d = 0; d < kDwords; ++d) {
      swiglu_gmem_store<4, false>(&out_dw[d], &out_vals[d]);
    }
  }
}

template <int MODE>
__device__ __forceinline__ float swiglu_variant_elem(
    float gate_raw, float gate_clamp, float up_clamp, float alpha, float limit) {
  if constexpr (MODE == 0) {
    return gate_clamp * swiglu_fast_sigmoid(alpha * gate_clamp) *
           (up_clamp + 1.0f);
  } else if constexpr (MODE == 1) {
    return gate_clamp * swiglu_fast_sigmoid(gate_clamp) * up_clamp;
  } else {
    const float silu_clamp =
        fminf(swiglu_fast_silu(gate_raw), limit);
    return silu_clamp * up_clamp;
  }
}

template <typename native_scalar_t, int VEC_SIZE, bool D_DIV, int MODE>
__device__ __forceinline__ void swiglu_variant_tile_scalar(
    const native_scalar_t* gate_ptr,
    const native_scalar_t* up_ptr,
    native_scalar_t* out_ptr,
    int d_base,
    int D,
    float alpha,
    float limit) {
#pragma unroll
  for (int i = 0; i < VEC_SIZE; ++i) {
    if (d_base + i >= D) {
      return;
    }
    const float gate_f = static_cast<float>(gate_ptr[i]);
    const float up_f = static_cast<float>(up_ptr[i]);
    const float g = swiglu_clamp_gate(gate_f, limit);
    const float tmp_up = swiglu_clamp_up(up_f, limit);
    float result_f;
    if constexpr (MODE == 0) {
      result_f = swiglu_variant_elem<0>(gate_f, g, tmp_up, alpha, limit);
    } else if constexpr (MODE == 1) {
      result_f = swiglu_variant_elem<1>(gate_f, g, tmp_up, alpha, limit);
    } else {
      result_f = swiglu_variant_elem<2>(gate_f, g, tmp_up, alpha, limit);
    }
    if constexpr (std::is_same_v<native_scalar_t, float>) {
      out_ptr[i] = result_f;
    } else {
      out_ptr[i] = b32_to_b16<native_scalar_t>(result_f);
    }
  }
}

template <typename native_scalar_t, int VEC_SIZE, bool D_DIV, int MODE>
__device__ __forceinline__ void swiglu_variant_tile(
    const uint32_t* gate_dw,
    const uint32_t* up_dw,
    uint32_t* out_dw,
    int d_base,
    int D,
    float alpha,
    float limit) {
  constexpr int kElemsPerDword =
      4 / static_cast<int>(sizeof(native_scalar_t));

  // vec=1 on fp16/bf16: one dword holds two elements; dword R/W corrupts neighbors.
  if constexpr (VEC_SIZE % kElemsPerDword != 0) {
    swiglu_variant_tile_scalar<native_scalar_t, VEC_SIZE, D_DIV, MODE>(
        reinterpret_cast<const native_scalar_t*>(gate_dw),
        reinterpret_cast<const native_scalar_t*>(up_dw),
        reinterpret_cast<native_scalar_t*>(out_dw), d_base, D, alpha, limit);
    return;
  }

  constexpr int kDwords = VEC_SIZE / kElemsPerDword;

  uint32_t gate_buf[kDwords];
  uint32_t up_buf[kDwords];

  const bool full_vec = (d_base + VEC_SIZE <= D);

  if constexpr (D_DIV) {
    // Full D-tile: wide coalesced loads; NT hints for streaming read-once input.
    swiglu_load_gate_up<kDwords, true>(gate_buf, up_buf, gate_dw, up_dw);
  } else if (full_vec) {
    // e.g. D=704 tile-0/1 with block_d=512: compile-time D_DIV is false but every
    // lane has a full vector — use the same wide NT path as aligned tiles.
    swiglu_load_gate_up<kDwords, true>(gate_buf, up_buf, gate_dw, up_dw);
  } else {
    if (d_base >= D) {
      return;
    }
#pragma unroll
    for (int d = 0; d < kDwords; ++d) {
      const int elem = d_base + d * kElemsPerDword;
      if (elem + kElemsPerDword <= D) {
        swiglu_gmem_load<4, false>(&gate_buf[d], &gate_dw[d]);
        swiglu_gmem_load<4, false>(&up_buf[d], &up_dw[d]);
      } else {
        gate_buf[d] = 0;
        up_buf[d] = 0;
        const native_scalar_t* gate_ptr =
            reinterpret_cast<const native_scalar_t*>(gate_dw) +
            d * kElemsPerDword;
        const native_scalar_t* up_ptr =
            reinterpret_cast<const native_scalar_t*>(up_dw) +
            d * kElemsPerDword;
        native_scalar_t* gate_out =
            reinterpret_cast<native_scalar_t*>(&gate_buf[d]);
        native_scalar_t* up_out =
            reinterpret_cast<native_scalar_t*>(&up_buf[d]);
#pragma unroll
        for (int i = 0; i < kElemsPerDword; ++i) {
          if (elem + i < D) {
            gate_out[i] = gate_ptr[i];
            up_out[i] = up_ptr[i];
          }
        }
      }
    }
  }

  const native_scalar_t* gate_vals =
      reinterpret_cast<const native_scalar_t*>(gate_buf);
  const native_scalar_t* up_vals =
      reinterpret_cast<const native_scalar_t*>(up_buf);

  native_scalar_t out_vals[VEC_SIZE];

#pragma unroll
  for (int i = 0; i < VEC_SIZE; ++i) {
    const float gate_f = static_cast<float>(gate_vals[i]);
    const float up_f = static_cast<float>(up_vals[i]);
    const float g = swiglu_clamp_gate(gate_f, limit);
    const float tmp_up = swiglu_clamp_up(up_f, limit);
    float result_f;
    if constexpr (MODE == 0) {
      result_f = swiglu_variant_elem<0>(gate_f, g, tmp_up, alpha, limit);
    } else if constexpr (MODE == 1) {
      result_f = swiglu_variant_elem<1>(gate_f, g, tmp_up, alpha, limit);
    } else {
      result_f = swiglu_variant_elem<2>(gate_f, g, tmp_up, alpha, limit);
    }
    if constexpr (std::is_same_v<native_scalar_t, float>) {
      out_vals[i] = result_f;
    } else {
      out_vals[i] = b32_to_b16<native_scalar_t>(result_f);
    }
  }

  if constexpr (D_DIV) {
    swiglu_store_out<kDwords>(
        out_dw, reinterpret_cast<const uint32_t*>(out_vals));
  } else if (full_vec) {
    swiglu_store_out<kDwords>(
        out_dw, reinterpret_cast<const uint32_t*>(out_vals));
  } else {
#pragma unroll
    for (int d = 0; d < kDwords; ++d) {
      const int elem = d_base + d * kElemsPerDword;
      if (elem + kElemsPerDword <= D) {
        swiglu_gmem_store<4, false>(
            &out_dw[d],
            &reinterpret_cast<const uint32_t*>(out_vals)[d]);
      } else {
        native_scalar_t* out_ptr =
            reinterpret_cast<native_scalar_t*>(out_dw) + d * kElemsPerDword;
#pragma unroll
        for (int i = 0; i < kElemsPerDword; ++i) {
          if (elem + i < D) {
            out_ptr[i] = out_vals[d * kElemsPerDword + i];
          }
        }
      }
    }
  }
}

template <int BLOCK_THREADS>
constexpr int swiglu_min_blocks_per_cu() {
  // warpSize=64: small blocks target 2 waves/CU; large D-tiles (e.g. 704) use 1.
  if (BLOCK_THREADS <= 128) {
    return 2;
  }
  return 1;
}

// Each block handles ROWS_PER_BLOCK consecutive M rows on the same D-tile.
template <typename scalar_t, int BLOCK_SIZE_D, int VEC_SIZE, int ROWS_PER_BLOCK,
          int MODE, bool D_DIV, bool M_DIV>
__launch_bounds__(BLOCK_SIZE_D / VEC_SIZE,
                  swiglu_min_blocks_per_cu<BLOCK_SIZE_D / VEC_SIZE>()) __global__
    void swiglu_variant_kernel(
        scalar_t* __restrict__ out,         // [M, D]
        const scalar_t* __restrict__ input, // [M, 2D]
        int M, int D, float alpha, float limit) {
  using native_scalar_t = native_t<scalar_t>;
  constexpr int kElemsPerDword =
      4 / static_cast<int>(sizeof(native_scalar_t));

  const int pid = blockIdx.x;
  const int num_pid_d = (D + BLOCK_SIZE_D - 1) / BLOCK_SIZE_D;
  const int pid_m_group = pid / num_pid_d;
  const int pid_d = pid - pid_m_group * num_pid_d;

  const int d_base = pid_d * BLOCK_SIZE_D + threadIdx.x * VEC_SIZE;
  if constexpr (!D_DIV) {
    if (d_base >= D) {
      return;
    }
  }
  const int m_base = pid_m_group * ROWS_PER_BLOCK;
  if constexpr (!M_DIV) {
    if (m_base >= M) {
      return;
    }
  }

#pragma unroll
  for (int r = 0; r < ROWS_PER_BLOCK; ++r) {
    // Row index is uniform within the block; promote to SGPR to save VGPR.
    const int pid_m = __builtin_amdgcn_readfirstlane(m_base + r);
    if constexpr (!M_DIV) {
      if (pid_m >= M) {
        continue;
      }
    }

    const int row_in_stride = 2 * D;
    const int in_row_off = pid_m * row_in_stride;
    const int out_row_off = pid_m * D;

    if constexpr (VEC_SIZE % kElemsPerDword != 0) {
      const native_scalar_t* gate_ptr =
          reinterpret_cast<const native_scalar_t*>(input + in_row_off) + d_base;
      const native_scalar_t* up_ptr =
          reinterpret_cast<const native_scalar_t*>(input + in_row_off + D) + d_base;
      native_scalar_t* out_ptr =
          reinterpret_cast<native_scalar_t*>(out + out_row_off) + d_base;

      swiglu_variant_tile_scalar<native_scalar_t, VEC_SIZE, D_DIV, MODE>(
          gate_ptr, up_ptr, out_ptr, d_base, D, alpha, limit);
    } else {
      const int dw_base = d_base / kElemsPerDword;
      const uint32_t* gate_dw =
          reinterpret_cast<const uint32_t*>(input + in_row_off) + dw_base;
      const uint32_t* up_dw =
          reinterpret_cast<const uint32_t*>(input + in_row_off + D) + dw_base;
      uint32_t* out_dw =
          reinterpret_cast<uint32_t*>(out + out_row_off) + dw_base;

      swiglu_variant_tile<native_scalar_t, VEC_SIZE, D_DIV, MODE>(
          gate_dw, up_dw, out_dw, d_base, D, alpha, limit);
    }
  }
}

template <typename scalar_t, int BLOCK_SIZE_D, int VEC_SIZE, int ROWS_PER_BLOCK,
          int MODE, bool D_DIV, bool M_DIV>
inline void launch_swiglu_variant_kernel(
    scalar_t* out_ptr, const scalar_t* in_ptr, int M, int D, float alpha,
    float limit, hipStream_t stream, int grid, int kThreads) {
  swiglu_variant_kernel<scalar_t, BLOCK_SIZE_D, VEC_SIZE, ROWS_PER_BLOCK,
                        MODE, D_DIV, M_DIV><<<grid, kThreads, 0, stream>>>(
      out_ptr, in_ptr, M, D, alpha, limit);
}

template <typename scalar_t, int BLOCK_SIZE_D, int VEC_SIZE, int ROWS_PER_BLOCK,
          int MODE>
inline void launch_swiglu_variant(
    scalar_t* out_ptr, const scalar_t* in_ptr, int M, int D, float alpha,
    float limit, hipStream_t stream) {
  constexpr int kThreads = BLOCK_SIZE_D / VEC_SIZE;
  static_assert(BLOCK_SIZE_D % VEC_SIZE == 0,
                "BLOCK_SIZE_D must be divisible by VEC_SIZE");

  const int num_pid_d = (D + BLOCK_SIZE_D - 1) / BLOCK_SIZE_D;
  const int num_pid_m = (M + ROWS_PER_BLOCK - 1) / ROWS_PER_BLOCK;
  const int grid = num_pid_m * num_pid_d;
  const bool d_div = (D % BLOCK_SIZE_D) == 0;
  const bool m_div = (M % ROWS_PER_BLOCK) == 0;

  if (d_div && m_div) {
    launch_swiglu_variant_kernel<scalar_t, BLOCK_SIZE_D, VEC_SIZE, ROWS_PER_BLOCK,
                                 MODE, true, true>(
        out_ptr, in_ptr, M, D, alpha, limit, stream, grid, kThreads);
  } else if (d_div && !m_div) {
    launch_swiglu_variant_kernel<scalar_t, BLOCK_SIZE_D, VEC_SIZE, ROWS_PER_BLOCK,
                                 MODE, true, false>(
        out_ptr, in_ptr, M, D, alpha, limit, stream, grid, kThreads);
  } else if (!d_div && m_div) {
    launch_swiglu_variant_kernel<scalar_t, BLOCK_SIZE_D, VEC_SIZE, ROWS_PER_BLOCK,
                                 MODE, false, true>(
        out_ptr, in_ptr, M, D, alpha, limit, stream, grid, kThreads);
  } else {
    launch_swiglu_variant_kernel<scalar_t, BLOCK_SIZE_D, VEC_SIZE, ROWS_PER_BLOCK,
                                 MODE, false, false>(
        out_ptr, in_ptr, M, D, alpha, limit, stream, grid, kThreads);
  }
}

template <typename scalar_t, int BLOCK_SIZE_D, int ROWS_PER_BLOCK>
inline void launch_swiglu_variant_vec(
    scalar_t* out_ptr, const scalar_t* in_ptr, int M, int D, float alpha,
    float limit, hipStream_t stream, int vec, int mode) {
  if (vec == 4) {
    if (mode == 0) {
      launch_swiglu_variant<scalar_t, BLOCK_SIZE_D, 4, ROWS_PER_BLOCK, 0>(
          out_ptr, in_ptr, M, D, alpha, limit, stream);
    } else if (mode == 1) {
      launch_swiglu_variant<scalar_t, BLOCK_SIZE_D, 4, ROWS_PER_BLOCK, 1>(
          out_ptr, in_ptr, M, D, alpha, limit, stream);
    } else {
      launch_swiglu_variant<scalar_t, BLOCK_SIZE_D, 4, ROWS_PER_BLOCK, 2>(
          out_ptr, in_ptr, M, D, alpha, limit, stream);
    }
  } else if (vec == 2) {
    if (mode == 0) {
      launch_swiglu_variant<scalar_t, BLOCK_SIZE_D, 2, ROWS_PER_BLOCK, 0>(
          out_ptr, in_ptr, M, D, alpha, limit, stream);
    } else if (mode == 1) {
      launch_swiglu_variant<scalar_t, BLOCK_SIZE_D, 2, ROWS_PER_BLOCK, 1>(
          out_ptr, in_ptr, M, D, alpha, limit, stream);
    } else {
      launch_swiglu_variant<scalar_t, BLOCK_SIZE_D, 2, ROWS_PER_BLOCK, 2>(
          out_ptr, in_ptr, M, D, alpha, limit, stream);
    }
  } else {
    if (mode == 0) {
      launch_swiglu_variant<scalar_t, BLOCK_SIZE_D, 1, ROWS_PER_BLOCK, 0>(
          out_ptr, in_ptr, M, D, alpha, limit, stream);
    } else if (mode == 1) {
      launch_swiglu_variant<scalar_t, BLOCK_SIZE_D, 1, ROWS_PER_BLOCK, 1>(
          out_ptr, in_ptr, M, D, alpha, limit, stream);
    } else {
      launch_swiglu_variant<scalar_t, BLOCK_SIZE_D, 1, ROWS_PER_BLOCK, 2>(
          out_ptr, in_ptr, M, D, alpha, limit, stream);
    }
  }
}

template <typename scalar_t, int BLOCK_SIZE_D>
inline void launch_swiglu_variant_rows(
    scalar_t* out_ptr, const scalar_t* in_ptr, int M, int D, float alpha,
    float limit, hipStream_t stream, int vec, int rows_per_block, int mode) {
  switch (rows_per_block) {
    case 1:
      launch_swiglu_variant_vec<scalar_t, BLOCK_SIZE_D, 1>(
          out_ptr, in_ptr, M, D, alpha, limit, stream, vec, mode);
      break;
    case 2:
      launch_swiglu_variant_vec<scalar_t, BLOCK_SIZE_D, 2>(
          out_ptr, in_ptr, M, D, alpha, limit, stream, vec, mode);
      break;
    case 4:
      launch_swiglu_variant_vec<scalar_t, BLOCK_SIZE_D, 4>(
          out_ptr, in_ptr, M, D, alpha, limit, stream, vec, mode);
      break;
    case 8:
      launch_swiglu_variant_vec<scalar_t, BLOCK_SIZE_D, 8>(
          out_ptr, in_ptr, M, D, alpha, limit, stream, vec, mode);
      break;
    default:
      TORCH_CHECK(false,
                  "swiglu_variant: unsupported rows_per_block=", rows_per_block,
                  " (supported: 1, 2, 4, 8)");
  }
}

struct SwigluLaunchConfig {
  int block_d;
  int rows_per_block;
  int vec_size;
};

// Kernel launch sizes with explicit template instantiations.
constexpr int kSupportedBlockD[] = {128, 256, 512, 768, 1024, 1408, 2048};

inline bool is_supported_block_d(int block_d) {
  for (int bd : kSupportedBlockD) {
    if (bd == block_d) {
      return true;
    }
  }
  return false;
}

inline int align_block_d_warp(int block_d, int vec_size) {
  int threads = block_d / vec_size;
  if (threads % kWarpSize != 0) {
    const int warps = (threads + kWarpSize - 1) / kWarpSize;
    block_d = warps * kWarpSize * vec_size;
  }
  if (is_supported_block_d(block_d)) {
    return block_d;
  }
  if (block_d <= 128) {
    return 128;
  }
  if (block_d <= 256) {
    return 256;
  }
  if (block_d <= 512) {
    return 512;
  }
  if (block_d <= 768) {
    return 768;
  }
  if (block_d <= 1024) {
    return 1024;
  }
  if (block_d <= 1408) {
    return 1408;
  }
  if (block_d <= 2048) {
    return 2048;
  }
  return 2048;
}

inline int count_d_tiles(int D, int block_d) {
  return (D + block_d - 1) / block_d;
}

// Active threads on the last (possibly partial) D-tile.
inline int last_tile_active_threads(int D, int block_d, int vec_size) {
  const int rem = D % block_d;
  const int last_elems = (rem == 0) ? block_d : rem;
  return (last_elems + vec_size - 1) / vec_size;
}

inline int active_threads_for_d(int D, int vec_size) {
  return (D + vec_size - 1) / vec_size;
}

// Large-M vec=2: keep >=256 threads for coalesced D-tile width.
constexpr int kMinThreadsLargeM = 256;
// Large-M vec=4: compute-bound shapes tolerate 192 threads (3 warps).
constexpr int kMinThreadsLargeMVec4 = 192;

inline bool is_valid_thread_config(int block_d, int vec_size) {
  if (block_d % vec_size != 0) {
    return false;
  }
  const int threads = block_d / vec_size;
  // gfx936 launch limit; MoE D=2048 @ vec=2 uses 1024 threads (16 warps).
  constexpr int kMaxThreadsPerBlock = 1024;
  return threads >= kWarpSize && (threads % kWarpSize) == 0 &&
         threads <= kMaxThreadsPerBlock;
}

// True when D itself is a warp-aligned single-tile width (e.g. D=1408/2048).
inline bool is_exact_d_tile_fit(int D, int vec_size) {
  return is_valid_thread_config(D, vec_size) && is_supported_block_d(D);
}

inline int score_launch_pair(int D, int block_d, int vec_size, int M) {
  const int tiles = count_d_tiles(D, block_d);
  const int threads = block_d / vec_size;
  const int active = active_threads_for_d(D, vec_size);
  const int idle = (tiles == 1) ? (threads - active) : 0;
  const int padding = tiles * block_d - D;

  // Single D-tile avoids revisiting rows; minimize idle lanes.
  int score = 0;
  if (tiles == 1) {
    score += 1'000'000;
  }
  score += threads * 100;
  score -= idle * 500;
  score -= padding;
  score -= (tiles - 1) * 50'000;
  // Large-M single-tile kernels are compute-bound: wider vec amortizes sigmoid VALU.
  if (tiles == 1 && M >= 4096) {
    score += vec_size * 20'000;
  }
  // Zero-padding exact D match (e.g. block_d=D=1408/2048).
  if (tiles == 1 && block_d == D) {
    score += 50'000;
  }
  // Compute-bound single-tile: >512 threads (e.g. D=2048 @ vec=2) hurts CU occupancy.
  if (tiles == 1 && M >= 4096 && threads > 512) {
    score -= (threads - 512) * 40;
  }
  return score;
}

inline SwigluLaunchConfig pick_small_m_config(int vec_size) {
  SwigluLaunchConfig cfg;
  cfg.block_d = 128;
  cfg.vec_size = (vec_size == 1) ? 1 : 2;
  cfg.rows_per_block = 2;
  return cfg;
}

// D=2048 exact single-tile: tiered row batching for prefill M buckets.
// Targets M in {4096, 8192, 16384, 32768} with M_DIV-friendly divisors.
inline int pick_rows_for_d2048_exact(int M, int block_d, int D) {
  if (block_d != D || D != 2048 || M < 4096) {
    return 0;
  }
  if (M >= 32768 && (M % 8) == 0) {
    return 8;
  }
  if (M >= 8192 && (M % 4) == 0) {
    return 4;
  }
  if (M >= 4096 && (M % 2) == 0) {
    return 2;
  }
  return 0;
}

// Amortize launch: pack more rows when M is large and D-tiles are few.
inline int pick_rows_per_block(
    int M, int rows_per_block, int block_d, int D, int vec_size) {
  if (rows_per_block != 1) {
    return rows_per_block;
  }
  if (M <= 16) {
    if (M <= 2) {
      return 8;
    }
    if (M <= 4) {
      return 4;
    }
    return 2;
  }
  if (M >= 4096) {
    const int d_tiles = count_d_tiles(D, block_d);
    if (d_tiles == 1) {
      const int d2048_rows = pick_rows_for_d2048_exact(M, block_d, D);
      if (d2048_rows > 0) {
        return d2048_rows;
      }
      // One D pass per row batch — safe to amortize row loop aggressively.
      if (M >= 65536) {
        return 8;
      }
      if (M >= 32768) {
        return 4;
      }
      if (M >= 16384) {
        return 2;
      }
      return 1;
    }
    const int threads = block_d / vec_size;
    const int active_last = last_tile_active_threads(D, block_d, vec_size);
    const int tail_fill_pct = (active_last * 100) / threads;
    if (d_tiles == 2 && tail_fill_pct >= 75) {
      if (M >= 65536) {
        return 4;
      }
      if (M >= 32768) {
        return 2;
      }
    }
    return 1;
  }
  if (M >= 256) {
    return 2;
  }
  if (M >= 64) {
    return 2;
  }
  return 1;
}

// Joint (block_d, vec) search tuned for gfx936-class (warpSize=64, 1.8 TB/s HBM).
inline SwigluLaunchConfig pick_swiglu_launch_config(
    int M, int D, int rows_per_block, int vec_size) {
  if (M <= 16) {
    SwigluLaunchConfig cfg = pick_small_m_config(vec_size);
    cfg.block_d = align_block_d_warp(cfg.block_d, cfg.vec_size);
    cfg.rows_per_block =
        pick_rows_per_block(M, rows_per_block, cfg.block_d, D, cfg.vec_size);
    return cfg;
  }

  // Fast path: D=2048 MoE prefill — single tile, vec=4, tiered rows_per_block.
  if (D == 2048 && M >= 4096 && vec_size != 1 &&
      is_exact_d_tile_fit(D, 4)) {
    SwigluLaunchConfig cfg;
    cfg.block_d = 2048;
    cfg.vec_size = 4;
    cfg.rows_per_block =
        pick_rows_per_block(M, rows_per_block, cfg.block_d, D, cfg.vec_size);
    return cfg;
  }

  SwigluLaunchConfig cfg;
  cfg.block_d = 512;
  cfg.vec_size = 2;
  int best_score = INT_MIN;

  constexpr int kBlockDCandidates[] = {256, 512, 768, 1024, 1408, 2048};
  constexpr int kVecCandidates[] = {2, 4};

  auto consider_config = [&](int bd, int vec) {
    if (vec_size == 1 && vec != 1) {
      return;
    }
    if (!is_valid_thread_config(bd, vec)) {
      return;
    }
    if (!is_supported_block_d(bd) && bd != D) {
      return;
    }
    const int threads = bd / vec;
    const int min_threads =
        (vec == 4) ? kMinThreadsLargeMVec4 : kMinThreadsLargeM;
    if (M >= 4096 && threads < min_threads) {
      return;
    }
    const int score = score_launch_pair(D, bd, vec, M);
    if (score > best_score) {
      best_score = score;
      cfg.block_d = bd;
      cfg.vec_size = vec;
    }
  };

  // MoE widths like D=1408/2048: exact single D-tile, zero padding.
  if (is_exact_d_tile_fit(D, 2)) {
    consider_config(D, 2);
  }
  if (is_exact_d_tile_fit(D, 4)) {
    consider_config(D, 4);
  }

  for (int bd : kBlockDCandidates) {
    if (D > 2048 && bd < 2048) {
      continue;
    } else if (D > 1024 && bd < 1024) {
      continue;
    }
    for (int vec : kVecCandidates) {
      consider_config(bd, vec);
    }
  }

  const bool exact_d_tile = (cfg.block_d == D);
  if (!exact_d_tile) {
    cfg.block_d = align_block_d_warp(cfg.block_d, cfg.vec_size);
  }
  cfg.rows_per_block =
      pick_rows_per_block(M, rows_per_block, cfg.block_d, D, cfg.vec_size);
  return cfg;
}

void swiglu_variant(torch::Tensor& out, torch::Tensor& input,
                    float alpha, float limit, int mode,
                    int rows_per_block = 1, int vec_size = 2) {
  TORCH_CHECK(input.is_cuda(), "swiglu_variant: input must be CUDA tensor");
  TORCH_CHECK(out.is_cuda(), "swiglu_variant: out must be CUDA tensor");
  TORCH_CHECK(input.is_contiguous(), "swiglu_variant: input must be contiguous");
  TORCH_CHECK(out.is_contiguous(), "swiglu_variant: out must be contiguous");
  TORCH_CHECK(input.scalar_type() == out.scalar_type(),
              "swiglu_variant: input and out dtype mismatch");
  TORCH_CHECK(input.dim() >= 1, "swiglu_variant: input dim must be >= 1");
  TORCH_CHECK(input.size(-1) % 2 == 0,
              "swiglu_variant: input last dim must be even");
  TORCH_CHECK(out.dim() == input.dim(), "swiglu_variant: rank mismatch");
  TORCH_CHECK(out.size(-1) * 2 == input.size(-1),
              "swiglu_variant: out last dim should be input last dim / 2");
  for (int64_t i = 0; i < input.dim() - 1; ++i) {
    TORCH_CHECK(out.size(i) == input.size(i),
                "swiglu_variant: shape mismatch at dim ", i);
  }

  const int64_t M64 = input.numel() / input.size(-1);
  const int64_t D64 = input.size(-1) / 2;
  TORCH_CHECK(M64 <= INT_MAX && D64 <= INT_MAX,
              "swiglu_variant: shape too large");
  const int M = static_cast<int>(M64);
  const int D = static_cast<int>(D64);
  if (M == 0 || D == 0) {
    return;
  }

  TORCH_CHECK(vec_size == 1 || vec_size == 2 || vec_size == 4,
              "swiglu_variant: vec_size must be 1, 2, or 4");
  TORCH_CHECK(rows_per_block == 1 || rows_per_block == 2 ||
                  rows_per_block == 4 || rows_per_block == 8,
              "swiglu_variant: rows_per_block must be 1, 2, 4, or 8");
  TORCH_CHECK(mode == 0 || mode == 1 || mode == 2,
              "swiglu_variant: mode must be 0, 1, or 2");

  const SwigluLaunchConfig cfg =
      pick_swiglu_launch_config(M, D, rows_per_block, vec_size);
  const int block_d = cfg.block_d;
  const int rows = cfg.rows_per_block;
  const int vec = cfg.vec_size;

  TORCH_CHECK(block_d % vec == 0,
              "swiglu_variant: block_d=", block_d,
              " must be divisible by vec_size=", vec);
  TORCH_CHECK((block_d / vec) % kWarpSize == 0,
              "swiglu_variant: threads per block must be a multiple of warpSize");

  const at::hip::OptionalHIPGuardMasqueradingAsCUDA device_guard(device_of(input));
  const hipStream_t stream = at::hip::getCurrentHIPStream();

  AITER_DISPATCH_FLOATING16_TYPES(input.scalar_type(), "swiglu_variant", [&] {
    auto* out_ptr = out.data_ptr<scalar_t>();
    const auto* in_ptr = input.data_ptr<scalar_t>();

    switch (block_d) {
      case 128:
        launch_swiglu_variant_rows<scalar_t, 128>(
            out_ptr, in_ptr, M, D, alpha, limit, stream, vec, rows, mode);
        break;
      case 256:
        launch_swiglu_variant_rows<scalar_t, 256>(
            out_ptr, in_ptr, M, D, alpha, limit, stream, vec, rows, mode);
        break;
      case 512:
        launch_swiglu_variant_rows<scalar_t, 512>(
            out_ptr, in_ptr, M, D, alpha, limit, stream, vec, rows, mode);
        break;
      case 768:
        launch_swiglu_variant_rows<scalar_t, 768>(
            out_ptr, in_ptr, M, D, alpha, limit, stream, vec, rows, mode);
        break;
      case 1024:
        launch_swiglu_variant_rows<scalar_t, 1024>(
            out_ptr, in_ptr, M, D, alpha, limit, stream, vec, rows, mode);
        break;
      case 1408:
        launch_swiglu_variant_rows<scalar_t, 1408>(
            out_ptr, in_ptr, M, D, alpha, limit, stream, vec, rows, mode);
        break;
      case 2048:
        launch_swiglu_variant_rows<scalar_t, 2048>(
            out_ptr, in_ptr, M, D, alpha, limit, stream, vec, rows, mode);
        break;
      default:
        TORCH_CHECK(false, "swiglu_variant: unsupported block_d=", block_d);
    }
  });
}

}  // namespace aiter
