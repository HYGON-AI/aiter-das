// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
// SPDX-License-Identifier: MIT

#include "sampling.h"

#include <ATen/hip/HIPContext.h>
#include <ATen/hip/impl/HIPGuardImplMasqueradingAsCUDA.h>
#include <c10/cuda/CUDAStream.h>
#include <torch/all.h>

#include <hip/hip_runtime.h>
#include <hipcub/hipcub.hpp>
#include <hiprand.h>
#include <hiprand_kernel.h>

// DTK's warp-sync intrinsics require HIP_ENABLE_WARP_SYNC_BUILTINS; fall back
// to the non-sync variants (behaviorally equivalent on AMD, warps execute
// lock-step within a wavefront).
#ifndef __shfl_up_sync
#define __shfl_up_sync(mask, var, delta, ...) __shfl_up(var, delta)
#endif
#ifndef __shfl_xor_sync
#define __shfl_xor_sync(mask, var, lane_mask, ...) __shfl_xor(var, lane_mask)
#endif
#ifndef __shfl_sync
#define __shfl_sync(mask, var, src_lane, ...) __shfl(var, src_lane)
#endif

namespace aiter {
namespace sampling {

using namespace hipcub;

using MaxReduceOp = hipcub::Max;
using MinReduceOp = hipcub::Min;

#define DCU_WARP_SIZE 64
#define __INLINE__ inline __attribute__((always_inline)) __device__

constexpr BlockScanAlgorithm SCAN_ALGO = BLOCK_SCAN_WARP_SCANS;
constexpr BlockReduceAlgorithm REDUCE_ALGO = BLOCK_REDUCE_WARP_REDUCTIONS;
// Wide blocks (1024t = 16 waves) hide the per-chunk sync latency best when the
// grid is small (<=1 block/CU); once there are >=64 blocks the 40-wave CU
// capacity would queue 1024t blocks, so fall back to 512t.
static constexpr int kBlockThreadsLarge = 1024;
static constexpr int kBlockThreadsSmall = 512;

#define DISPATCH_BLOCK_THREADS(batch_size, THREADS, ...)                     \
  if ((batch_size) < 64) {                                                   \
    constexpr int THREADS = kBlockThreadsLarge;                              \
    __VA_ARGS__                                                              \
  } else {                                                                   \
    constexpr int THREADS = kBlockThreadsSmall;                              \
    __VA_ARGS__                                                              \
  }

#define DISPATCH_DETERMINISTIC(deterministic, DETERMINISTIC, ...) \
  if (deterministic) {                                            \
    constexpr bool DETERMINISTIC = true;                          \
    __VA_ARGS__                                                   \
  } else {                                                        \
    constexpr bool DETERMINISTIC = false;                         \
    __VA_ARGS__                                                   \
  }

template <typename T1, typename T2>
__forceinline__ __device__ __host__ constexpr T1 ceil_div(const T1 x, const T2 y) noexcept {
  return (x + y - 1) / y;
}

// Move block/wave-uniform scalars from VGPRs to SGPRs (values must be identical
// across the wave, otherwise results are wrong -- callers guarantee this).
__INLINE__ uint32_t rfl_u32(uint32_t v) {
  return (uint32_t)__builtin_amdgcn_readfirstlane((int)v);
}
__INLINE__ int rfl_i32(int v) { return __builtin_amdgcn_readfirstlane(v); }
__INLINE__ float rfl_f32(float v) {
  return __builtin_bit_cast(float, __builtin_amdgcn_readfirstlane(__builtin_bit_cast(int, v)));
}

template <typename float_t, size_t vec_size>
struct vec_t {
  __INLINE__ float_t& operator[](size_t i);
  __INLINE__ const float_t& operator[](size_t i) const;
  __INLINE__ void fill(float_t val);
  __INLINE__ void load(const float_t* ptr);
  __INLINE__ void store(float_t* ptr) const;
  template <typename T>
  __INLINE__ void cast_from(const vec_t<T, vec_size>& src);
  template <typename T>
  __INLINE__ void cast_load(const T* ptr);
  template <typename T>
  __INLINE__ void cast_store(T* ptr) const;
};

template <typename dst_t, typename src_t>
struct vec_cast {
  template <size_t vec_size>
  __INLINE__ static void cast(dst_t* dst, const src_t* src) {
#pragma unroll
    for (size_t i = 0; i < vec_size; ++i) {
      dst[i] = (dst_t)src[i];
    }
  }
};

template <typename src_float_t, typename tgt_float_t, size_t vec_size>
__INLINE__ void cast_from_impl(vec_t<tgt_float_t, vec_size>& dst,
                               const vec_t<src_float_t, vec_size>& src) {
  vec_cast<tgt_float_t, src_float_t>::template cast<vec_size>(
      dst.ptr(), const_cast<vec_t<src_float_t, vec_size>*>(&src)->ptr());
}

template <typename src_float_t, typename tgt_float_t, size_t vec_size>
__INLINE__ void cast_load_impl(vec_t<tgt_float_t, vec_size>& dst,
                               const src_float_t* src_ptr) {
  if constexpr (std::is_same_v<src_float_t, tgt_float_t>) {
    dst.load(src_ptr);
  } else {
    vec_t<src_float_t, vec_size> tmp;
    tmp.load(src_ptr);
    dst.cast_from(tmp);
  }
}

template <typename src_float_t, typename tgt_float_t, size_t vec_size>
__INLINE__ void cast_store_impl(tgt_float_t* dst_ptr,
                                const vec_t<src_float_t, vec_size>& src) {
  if constexpr (std::is_same_v<src_float_t, tgt_float_t>) {
    src.store(dst_ptr);
  } else {
    vec_t<tgt_float_t, vec_size> tmp;
    tmp.cast_from(src);
    tmp.store(dst_ptr);
  }
}

template <size_t vec_size>
struct vec_t<float, vec_size> {
  static_assert(vec_size % 4 == 0, "Invalid vector size");
  float4 data[vec_size / 4];

  __INLINE__ float& operator[](size_t i) { return ((float*)(data))[i]; }
  __INLINE__ const float& operator[](size_t i) const { return ((const float*)(data))[i]; }
  __INLINE__ float* ptr() { return reinterpret_cast<float*>(&data); }
  __INLINE__ void fill(float val) {
#pragma unroll
    for (size_t i = 0; i < vec_size / 4; ++i) {
      data[i] = make_float4(val, val, val, val);
    }
  }
  __INLINE__ void load(const float* ptr) {
#pragma unroll
    for (size_t i = 0; i < vec_size / 4; ++i) {
      data[i] = ((float4*)ptr)[i];
    }
  }
  __INLINE__ void store(float* ptr) const {
#pragma unroll
    for (size_t i = 0; i < vec_size / 4; ++i) {
      ((float4*)ptr)[i] = data[i];
    }
  }
  template <typename T>
  __INLINE__ void cast_load(const T* ptr) {
    cast_load_impl(*this, ptr);
  }
  template <typename T>
  __INLINE__ void cast_store(T* ptr) const {
    cast_store_impl(ptr, *this);
  }
};

template <typename T>
struct ValueCount {
  T value;
  int count;

  __device__ ValueCount operator+(const ValueCount& other) const {
    return {value + other.value, count + other.count};
  }
  __device__ ValueCount& operator+=(const ValueCount& other) {
    value += other.value;
    count += other.count;
    return *this;
  }
};

template <uint32_t BLOCK_THREADS, BlockScanAlgorithm SCAN_ALGORITHM,
          BlockReduceAlgorithm REDUCE_ALGORITHM>
struct SamplingTempStorage {
  union {
    float deterministic_scan[BLOCK_THREADS / DCU_WARP_SIZE];
    typename BlockScan<float, BLOCK_THREADS, SCAN_ALGORITHM>::TempStorage scan;
    typename BlockReduce<float, BLOCK_THREADS, REDUCE_ALGORITHM>::TempStorage reduce;
    typename BlockReduce<int, BLOCK_THREADS, REDUCE_ALGORITHM>::TempStorage reduce_int;
    typename BlockReduce<ValueCount<float>, BLOCK_THREADS, REDUCE_ALGORITHM>::TempStorage
        reduce_value_count;
    typename BlockAdjacentDifference<bool, BLOCK_THREADS>::TempStorage adj_diff;
  } block_prim;
  struct {
    int32_t sampled_id;
    int32_t last_valid_id;
    float max_val;
    union {
      float value;
      ValueCount<float> pair;
    } block_aggregate;
  };
};

struct BoolDiffOp {
  __device__ __forceinline__ bool operator()(const bool& lhs, const bool& rhs) const {
    return lhs != rhs;
  }
};

template <uint32_t VEC_SIZE, uint32_t BLOCK_THREADS, BlockScanAlgorithm SCAN_ALGORITHM,
          BlockReduceAlgorithm REDUCE_ALGORITHM>
__device__ __forceinline__ void DeterministicInclusiveSum(
    const float* in_data, float* out_data,
    SamplingTempStorage<BLOCK_THREADS, SCAN_ALGORITHM, REDUCE_ALGORITHM>* temp_storage) {
  float* smem_prefix_sum = temp_storage->block_prim.deterministic_scan;
  float thread_data[VEC_SIZE];
  float thread_sum = 0;
#pragma unroll
  for (uint32_t i = 0; i < VEC_SIZE; ++i) {
    thread_sum += in_data[i];
    thread_data[i] = thread_sum;
  }

  float thread_exclusive_prefix_sum = thread_sum;

#pragma unroll
  for (uint32_t offset = 1; offset < DCU_WARP_SIZE; offset *= 2) {
    float tmp = __shfl_up_sync(0xffffffffffffffff, thread_exclusive_prefix_sum, offset);
    if ((threadIdx.x + 1) % (offset * 2) == 0) {
      thread_exclusive_prefix_sum += tmp;
    }
  }

  float warp_sum = __shfl_sync(0xffffffffffffffff, thread_exclusive_prefix_sum,
                               threadIdx.x | 0xffffffffffffffff);
  if (threadIdx.x % DCU_WARP_SIZE == DCU_WARP_SIZE - 1) {
    thread_exclusive_prefix_sum = 0;
  }

#pragma unroll
  for (uint32_t offset = DCU_WARP_SIZE / 2; offset >= 1; offset /= 2) {
    float tmp = __shfl_xor_sync(0xffffffffffffffff, thread_exclusive_prefix_sum, offset);
    if ((threadIdx.x + 1) % (offset * 2) == 0) {
      thread_exclusive_prefix_sum = tmp + thread_exclusive_prefix_sum;
    }
    if ((threadIdx.x + 1) % (offset * 2) == offset) {
      thread_exclusive_prefix_sum = tmp;
    }
  }

  smem_prefix_sum[threadIdx.x / DCU_WARP_SIZE] = warp_sum;
  __syncthreads();

  if (threadIdx.x < DCU_WARP_SIZE) {
    float warp_exclusive_prefix_sum =
        (threadIdx.x < BLOCK_THREADS / DCU_WARP_SIZE) ? smem_prefix_sum[threadIdx.x] : 0;

#pragma unroll
    for (uint32_t offset = 1; offset < DCU_WARP_SIZE; offset *= 2) {
      float tmp = __shfl_up_sync(0xffffffffffffffff, warp_exclusive_prefix_sum, offset);
      if ((threadIdx.x + 1) % (offset * 2) == 0) {
        warp_exclusive_prefix_sum += tmp;
      }
    }

    if (threadIdx.x % DCU_WARP_SIZE == DCU_WARP_SIZE - 1) {
      warp_exclusive_prefix_sum = 0;
    }

#pragma unroll
    for (uint32_t offset = DCU_WARP_SIZE / 2; offset >= 1; offset /= 2) {
      float tmp = __shfl_xor_sync(0xffffffffffffffff, warp_exclusive_prefix_sum, offset);
      if ((threadIdx.x + 1) % (offset * 2) == 0) {
        warp_exclusive_prefix_sum = tmp + warp_exclusive_prefix_sum;
      }
      if ((threadIdx.x + 1) % (offset * 2) == offset) {
        warp_exclusive_prefix_sum = tmp;
      }
    }
    if (threadIdx.x < BLOCK_THREADS / DCU_WARP_SIZE) {
      smem_prefix_sum[threadIdx.x] = warp_exclusive_prefix_sum;
    }
  }
  __syncthreads();

#pragma unroll
  for (uint32_t i = 0; i < VEC_SIZE; ++i) {
    out_data[i] =
        smem_prefix_sum[threadIdx.x / DCU_WARP_SIZE] + thread_exclusive_prefix_sum + thread_data[i];
  }
}

template <uint32_t VEC_SIZE, uint32_t BLOCK_THREADS, BlockScanAlgorithm SCAN_ALGORITHM,
          BlockReduceAlgorithm REDUCE_ALGORITHM, bool DETERMINISTIC, typename Predicate>
__device__ __forceinline__ void DeviceSamplingFromProb(
    uint32_t i, uint32_t d, Predicate pred, float u, vec_t<float, VEC_SIZE> prob_vec,
    float& aggregate, bool track_max,
    SamplingTempStorage<BLOCK_THREADS, SCAN_ALGORITHM, REDUCE_ALGORITHM>* temp_storage) {
  const uint32_t tx = threadIdx.x;
  float prob_greater_than_threshold[VEC_SIZE];
  float inclusive_cdf[VEC_SIZE];
  bool greater_than_u[VEC_SIZE], valid[VEC_SIZE];
#pragma unroll
  for (uint32_t j = 0; j < VEC_SIZE; ++j) {
    prob_greater_than_threshold[j] = pred(prob_vec[j]) ? prob_vec[j] : 0;
    valid[j] = pred(prob_vec[j]) && (i * BLOCK_THREADS + tx) * VEC_SIZE + j < d;
  }

  // Piggyback row-max tracking (probs are non-negative floats, so the bit
  // pattern is order-preserving). One smem atomicMax per wave per chunk, no
  // barrier; consumed after the first round's CDF pass to tighten the
  // rejection bracket (high starts at 1.0 but never exceeds the row max).
  // Gated to the first round only: later rounds already have high <= row_max.
  if (track_max) {
    float lane_max = 0;
#pragma unroll
    for (uint32_t j = 0; j < VEC_SIZE; ++j) {
      lane_max = prob_vec[j] > lane_max ? prob_vec[j] : lane_max;
    }
#pragma unroll
    for (uint32_t offset = DCU_WARP_SIZE / 2; offset > 0; offset /= 2) {
      lane_max = fmaxf(lane_max, __shfl_xor_sync(0xffffffffffffffff, lane_max, offset));
    }
    if (tx % DCU_WARP_SIZE == 0) {
      atomicMax((int*)&temp_storage->max_val, __float_as_int(lane_max));
    }
  }
  float aggregate_local =
      BlockReduce<float, BLOCK_THREADS, REDUCE_ALGORITHM>(temp_storage->block_prim.reduce)
          .template Sum<VEC_SIZE>(prob_greater_than_threshold);
  __syncthreads();
  if (tx == 0) {
    temp_storage->block_aggregate.value = aggregate_local;
  }
  __syncthreads();
  aggregate_local = temp_storage->block_aggregate.value;

  if (aggregate + aggregate_local > u) {
    if constexpr (DETERMINISTIC) {
      DeterministicInclusiveSum<VEC_SIZE, BLOCK_THREADS, SCAN_ALGORITHM, REDUCE_ALGORITHM>(
          prob_greater_than_threshold, inclusive_cdf, temp_storage);
    } else {
      BlockScan<float, BLOCK_THREADS, SCAN_ALGORITHM>(temp_storage->block_prim.scan)
          .template InclusiveSum<VEC_SIZE>(prob_greater_than_threshold, inclusive_cdf);

      __syncthreads();
    }

#pragma unroll
    for (uint32_t j = 0; j < VEC_SIZE; ++j) {
      greater_than_u[j] = (inclusive_cdf[j] + aggregate > u) && valid[j];
    }

    bool greater_than_u_diff[VEC_SIZE];
    BlockAdjacentDifference<bool, BLOCK_THREADS>(temp_storage->block_prim.adj_diff)
        .template FlagHeads<VEC_SIZE>(greater_than_u_diff, greater_than_u, BoolDiffOp(), 0);
    __syncthreads();

#pragma unroll
    for (uint32_t j = 0; j < VEC_SIZE; ++j) {
      if (greater_than_u_diff[j]) {
        atomicMin(&(temp_storage->sampled_id), (i * BLOCK_THREADS + tx) * VEC_SIZE + j);
      }
    }
    __syncthreads();
  }

  int valid_index[VEC_SIZE];
#pragma unroll
  for (uint32_t j = 0; j < VEC_SIZE; ++j) {
    if (valid[j]) {
      valid_index[j] = (i * BLOCK_THREADS + tx) * VEC_SIZE + j;
    } else {
      valid_index[j] = -1;
    }
  }
  int max_valid_index =
      BlockReduce<int, BLOCK_THREADS, REDUCE_ALGORITHM>(temp_storage->block_prim.reduce_int)
          .Reduce(valid_index, MaxReduceOp{});
  __syncthreads();
  if (tx == 0 && max_valid_index != -1) {
    temp_storage->last_valid_id = max_valid_index;
  }
  __syncthreads();
  aggregate += aggregate_local;
}

template <uint32_t BLOCK_THREADS, BlockScanAlgorithm SCAN_ALGORITHM,
          BlockReduceAlgorithm REDUCE_ALGORITHM, uint32_t VEC_SIZE, bool DETERMINISTIC,
          typename DType, typename IdType>
__global__ void TopKSamplingFromProbKernel(DType* probs, IdType* output, IdType* indices,
                                           IdType* top_k_arr, uint32_t top_k_val, uint32_t d,
                                           uint64_t philox_seed, uint64_t philox_offset) {
  const uint32_t bx = blockIdx.x, tx = threadIdx.x;
  hiprandStatePhilox4_32_10_t state;
  hiprand_init(philox_seed, bx, philox_offset, &state);
  const uint32_t k = rfl_u32(top_k_arr == nullptr ? top_k_val : top_k_arr[bx]);
  const uint32_t row_idx = rfl_u32(indices == nullptr ? bx : indices[bx]);

  extern __shared__ __align__(
      alignof(SamplingTempStorage<BLOCK_THREADS, SCAN_ALGORITHM, REDUCE_ALGORITHM>))
      uint8_t smem_sampling[];
  auto& temp_storage =
      reinterpret_cast<SamplingTempStorage<BLOCK_THREADS, SCAN_ALGORITHM, REDUCE_ALGORITHM>&>(
          smem_sampling);

  vec_t<float, VEC_SIZE> probs_vec;
  float aggregate;
  bool row_scan_done = false;
  float q = 1;
  double low = 0, high = 1.f;
  int sampled_id;
  int round = 0;
  do {
    round += 1;
    if (tx == 0) {
      temp_storage.sampled_id = d;
      temp_storage.max_val = 0;
    }
    __syncthreads();
    const float u = rfl_f32(hiprand_uniform(&state) * q);
    aggregate = 0;
    row_scan_done = true;
#pragma unroll 4
    for (uint32_t i = 0; i < ceil_div(d, BLOCK_THREADS * VEC_SIZE); ++i) {
      probs_vec.fill(0);
      if ((i * BLOCK_THREADS + tx) * VEC_SIZE < d) {
        probs_vec.cast_load(probs + row_idx * d + (i * BLOCK_THREADS + tx) * VEC_SIZE);
      }

      DeviceSamplingFromProb<VEC_SIZE, BLOCK_THREADS, SCAN_ALGORITHM, REDUCE_ALGORITHM,
                             DETERMINISTIC>(
          i, d, [&](float x) { return x > low; }, u, probs_vec, aggregate,
          round == 1 && k < d, &temp_storage);
      if (aggregate > u) {
        row_scan_done = false;
        break;
      }
    }
    __syncthreads();
    sampled_id = temp_storage.sampled_id;
    if (sampled_id == d) {
      sampled_id = temp_storage.last_valid_id;
    }
    if (round == 1) {
      // The k-th / p-mass threshold never exceeds the row max: bracket the
      // search by [.., row_max] instead of [.., 1.0] to cut the number of
      // bisection rounds on flat distributions. Only trust max_val after a
      // full-row scan: the early break above stops the max tracking mid-row,
      // and a prefix max can collapse the bracket onto the sampled token and
      // emit a token outside the top-k.
      high = row_scan_done ? (double)(temp_storage.max_val) : 1.0;
    }
    const double pivot_0 = (double)rfl_f32(probs[row_idx * d + sampled_id]);
    double pivot_1 = (pivot_0 + high) / 2;

    ValueCount<float> aggregate_gt_pivot_0{0, 0}, aggregate_gt_pivot_1{0, 0};
    ValueCount<float> threadlocal_gt_pivot_0{0, 0}, threadlocal_gt_pivot_1{0, 0};
#pragma unroll 4
    for (uint32_t i = 0; i < ceil_div(d, BLOCK_THREADS * VEC_SIZE); ++i) {
      probs_vec.fill(0);
      if ((i * BLOCK_THREADS + tx) * VEC_SIZE < d) {
        probs_vec.cast_load(probs + row_idx * d + (i * BLOCK_THREADS + tx) * VEC_SIZE);
      }

      ValueCount<float> probs_gt_pivot_0[VEC_SIZE], probs_gt_pivot_1[VEC_SIZE];
#pragma unroll
      for (uint32_t j = 0; j < VEC_SIZE; ++j) {
        probs_gt_pivot_0[j] = {
            (probs_vec[j] > pivot_0) ? probs_vec[j] : 0,
            (probs_vec[j] > pivot_0 && (i * BLOCK_THREADS + tx) * VEC_SIZE + j < d)};
        probs_gt_pivot_1[j] = {
            (probs_vec[j] > pivot_1) ? probs_vec[j] : 0,
            (probs_vec[j] > pivot_1 && (i * BLOCK_THREADS + tx) * VEC_SIZE + j < d)};
        threadlocal_gt_pivot_0 += probs_gt_pivot_0[j];
        threadlocal_gt_pivot_1 += probs_gt_pivot_1[j];
      }
    }
    aggregate_gt_pivot_0 += BlockReduce<ValueCount<float>, BLOCK_THREADS, REDUCE_ALGORITHM>(
                                temp_storage.block_prim.reduce_value_count)
                                .Sum(threadlocal_gt_pivot_0);
    if (tx == 0) {
      temp_storage.block_aggregate.pair = aggregate_gt_pivot_0;
    }
    __syncthreads();
    aggregate_gt_pivot_0 = temp_storage.block_aggregate.pair;

    aggregate_gt_pivot_1 += BlockReduce<ValueCount<float>, BLOCK_THREADS, REDUCE_ALGORITHM>(
                                temp_storage.block_prim.reduce_value_count)
                                .Sum(threadlocal_gt_pivot_1);
    if (tx == 0) {
      temp_storage.block_aggregate.pair = aggregate_gt_pivot_1;
    }
    __syncthreads();
    aggregate_gt_pivot_1 = temp_storage.block_aggregate.pair;
    if (aggregate_gt_pivot_0.count < static_cast<int>(k)) {
      break;
    }
    if (aggregate_gt_pivot_1.count < static_cast<int>(k)) {
      low = pivot_0;
      high = pivot_1;
      q = aggregate_gt_pivot_0.value;
    } else {
      low = pivot_1;
      q = aggregate_gt_pivot_1.value;
    }
  } while (low < high);
  __syncthreads();
  if (tx == 0) {
    output[bx] = sampled_id;
  }
}

template <uint32_t BLOCK_THREADS, BlockScanAlgorithm SCAN_ALGORITHM,
          BlockReduceAlgorithm REDUCE_ALGORITHM, uint32_t VEC_SIZE, bool DETERMINISTIC,
          typename DType, typename IdType>
__global__ void TopPSamplingFromProbKernel(DType* probs, IdType* output, IdType* indices,
                                           float* top_p_arr, float top_p_val, uint32_t d,
                                           uint64_t philox_seed, uint64_t philox_offset) {
  const uint32_t bx = blockIdx.x, tx = threadIdx.x;
  hiprandStatePhilox4_32_10_t state;
  hiprand_init(philox_seed, bx, philox_offset, &state);
  const uint32_t row_idx = rfl_u32(indices == nullptr ? bx : indices[bx]);
  const float top_p = rfl_f32((top_p_arr == nullptr) ? top_p_val : top_p_arr[row_idx]);

  extern __shared__ __align__(
      alignof(SamplingTempStorage<BLOCK_THREADS, SCAN_ALGORITHM, REDUCE_ALGORITHM>))
      uint8_t smem_sampling[];
  auto& temp_storage =
      reinterpret_cast<SamplingTempStorage<BLOCK_THREADS, SCAN_ALGORITHM, REDUCE_ALGORITHM>&>(
          smem_sampling);

  vec_t<float, VEC_SIZE> probs_vec;
  float aggregate;
  float q = 1;
  double low = 0, high = 1.f;
  int sampled_id;
  int round = 0;
  do {
    round += 1;
    if (tx == 0) {
      temp_storage.sampled_id = d;
      temp_storage.max_val = 0;
    }
    __syncthreads();
    const float u = rfl_f32(hiprand_uniform(&state) * q);
    aggregate = 0;
#pragma unroll 4
    for (uint32_t i = 0; i < ceil_div(d, BLOCK_THREADS * VEC_SIZE); ++i) {
      probs_vec.fill(0);
      if ((i * BLOCK_THREADS + tx) * VEC_SIZE < d) {
        probs_vec.cast_load(probs + row_idx * d + (i * BLOCK_THREADS + tx) * VEC_SIZE);
      }

      DeviceSamplingFromProb<VEC_SIZE, BLOCK_THREADS, SCAN_ALGORITHM, REDUCE_ALGORITHM,
                             DETERMINISTIC>(
          i, d, [&](float x) { return x > low; }, u, probs_vec, aggregate, false,
          &temp_storage);
      if (aggregate > u) {
        break;
      }
    }

    __syncthreads();
    sampled_id = temp_storage.sampled_id;
    if (sampled_id == d) {
      sampled_id = temp_storage.last_valid_id;
    }
    const double pivot_0 = (double)rfl_f32(probs[row_idx * d + sampled_id]);
    double pivot_1 = (pivot_0 + high) / 2;

    float aggregate_gt_pivot_0 = 0, aggregate_gt_pivot_1 = 0;
    float threadlocal_aggregate_gt_pivot_0 = 0;
    float threadlocal_aggregate_gt_pivot_1 = 0;
#pragma unroll 4
    for (uint32_t i = 0; i < ceil_div(d, BLOCK_THREADS * VEC_SIZE); ++i) {
      probs_vec.fill(0);
      if ((i * BLOCK_THREADS + tx) * VEC_SIZE < d) {
        probs_vec.cast_load(probs + row_idx * d + (i * BLOCK_THREADS + tx) * VEC_SIZE);
      }

      float probs_gt_pivot_0[VEC_SIZE], probs_gt_pivot_1[VEC_SIZE];
#pragma unroll
      for (uint32_t j = 0; j < VEC_SIZE; ++j) {
        probs_gt_pivot_0[j] = (probs_vec[j] > pivot_0) ? probs_vec[j] : 0;
        probs_gt_pivot_1[j] = (probs_vec[j] > pivot_1) ? probs_vec[j] : 0;
        threadlocal_aggregate_gt_pivot_0 += probs_gt_pivot_0[j];
        threadlocal_aggregate_gt_pivot_1 += probs_gt_pivot_1[j];
      }
    }
    aggregate_gt_pivot_0 += BlockReduce<float, BLOCK_THREADS>(temp_storage.block_prim.reduce)
                                .Sum(threadlocal_aggregate_gt_pivot_0);
    if (tx == 0) {
      temp_storage.block_aggregate.value = aggregate_gt_pivot_0;
    }
    __syncthreads();
    aggregate_gt_pivot_0 = temp_storage.block_aggregate.value;

    aggregate_gt_pivot_1 += BlockReduce<float, BLOCK_THREADS>(temp_storage.block_prim.reduce)
                                .Sum(threadlocal_aggregate_gt_pivot_1);
    if (tx == 0) {
      temp_storage.block_aggregate.value = aggregate_gt_pivot_1;
    }
    __syncthreads();
    aggregate_gt_pivot_1 = temp_storage.block_aggregate.value;

    if (aggregate_gt_pivot_0 < top_p) {
      break;
    }
    if (aggregate_gt_pivot_1 < top_p) {
      low = pivot_0;
      high = pivot_1;
      q = aggregate_gt_pivot_0;
    } else {
      low = pivot_1;
      q = aggregate_gt_pivot_1;
    }
  } while (low < high);
  __syncthreads();
  if (tx == 0) {
    output[bx] = sampled_id;
  }
}

template <uint32_t BLOCK_THREADS, BlockScanAlgorithm SCAN_ALGORITHM,
          BlockReduceAlgorithm REDUCE_ALGORITHM, uint32_t VEC_SIZE, bool DETERMINISTIC,
          typename DType, typename IdType>
__global__ void TopKTopPSamplingFromProbKernel(DType* probs, IdType* top_k_arr, float* top_p_arr,
                                               IdType* output, IdType* indices, IdType top_k_val,
                                               float top_p_val, uint32_t d, uint64_t philox_seed,
                                               uint64_t philox_offset) {
  const uint32_t bx = blockIdx.x, tx = threadIdx.x;
  hiprandStatePhilox4_32_10_t state;
  hiprand_init(philox_seed, bx, philox_offset, &state);
  const uint32_t row_idx = rfl_u32(indices == nullptr ? bx : indices[bx]);
  const uint32_t k = rfl_u32(top_k_arr == nullptr ? top_k_val : top_k_arr[row_idx]);
  const float p = rfl_f32(top_p_arr == nullptr ? top_p_val : top_p_arr[row_idx]);

  extern __shared__ __align__(
      alignof(SamplingTempStorage<BLOCK_THREADS, SCAN_ALGORITHM, REDUCE_ALGORITHM>))
      uint8_t smem_sampling[];
  auto& temp_storage =
      reinterpret_cast<SamplingTempStorage<BLOCK_THREADS, SCAN_ALGORITHM, REDUCE_ALGORITHM>&>(
          smem_sampling);

  vec_t<float, VEC_SIZE> probs_vec;
  float aggregate;
  bool row_scan_done = false;
  float q = 1;
  double low = 0, high = 1.f;
  int sampled_id;
  int round = 0;
  do {
    round += 1;
    if (tx == 0) {
      temp_storage.sampled_id = d;
      temp_storage.max_val = 0;
    }
    __syncthreads();
    const float u = rfl_f32(hiprand_uniform(&state) * q);
    aggregate = 0;
    row_scan_done = true;
#pragma unroll 4
    for (uint32_t i = 0; i < ceil_div(d, BLOCK_THREADS * VEC_SIZE); ++i) {
      probs_vec.fill(0);
      if ((i * BLOCK_THREADS + tx) * VEC_SIZE < d) {
        probs_vec.cast_load(probs + row_idx * d + (i * BLOCK_THREADS + tx) * VEC_SIZE);
      }

      DeviceSamplingFromProb<VEC_SIZE, BLOCK_THREADS, SCAN_ALGORITHM, REDUCE_ALGORITHM,
                             DETERMINISTIC>(
          i, d, [&](float x) { return x > low; }, u, probs_vec, aggregate,
          round == 1 && (k < d || p < 1.f), &temp_storage);
      if (aggregate > u) {
        row_scan_done = false;
        break;
      }
    }
    __syncthreads();
    sampled_id = temp_storage.sampled_id;
    if (sampled_id == d) {
      sampled_id = temp_storage.last_valid_id;
    }
    if (round == 1) {
      // The k-th / p-mass threshold never exceeds the row max: bracket the
      // search by [.., row_max] instead of [.., 1.0] to cut the number of
      // bisection rounds on flat distributions. Only trust max_val after a
      // full-row scan: the early break above stops the max tracking mid-row,
      // and a prefix max can collapse the bracket onto the sampled token and
      // emit a token outside the top-k / top-p set.
      high = row_scan_done ? (double)(temp_storage.max_val) : 1.0;
    }
    const double pivot_0 = (double)rfl_f32(probs[row_idx * d + sampled_id]);
    double pivot_1 = (pivot_0 + high) / 2;

    ValueCount<float> aggregate_gt_pivot_0{0, 0}, aggregate_gt_pivot_1{0, 0};
    ValueCount<float> threadlocal_aggregate_gt_pivot_0{0, 0};
    ValueCount<float> threadlocal_aggregate_gt_pivot_1{0, 0};
#pragma unroll 4
    for (uint32_t i = 0; i < ceil_div(d, BLOCK_THREADS * VEC_SIZE); ++i) {
      probs_vec.fill(0);
      if ((i * BLOCK_THREADS + tx) * VEC_SIZE < d) {
        probs_vec.cast_load(probs + row_idx * d + (i * BLOCK_THREADS + tx) * VEC_SIZE);
      }

      ValueCount<float> probs_gt_pivot_0[VEC_SIZE], probs_gt_pivot_1[VEC_SIZE];
#pragma unroll
      for (uint32_t j = 0; j < VEC_SIZE; ++j) {
        probs_gt_pivot_0[j] = {
            (probs_vec[j] > pivot_0) ? probs_vec[j] : 0,
            (probs_vec[j] > pivot_0 && (i * BLOCK_THREADS + tx) * VEC_SIZE + j < d)};
        probs_gt_pivot_1[j] = {
            (probs_vec[j] > pivot_1) ? probs_vec[j] : 0,
            (probs_vec[j] > pivot_1 && (i * BLOCK_THREADS + tx) * VEC_SIZE + j < d)};
        threadlocal_aggregate_gt_pivot_0 += probs_gt_pivot_0[j];
        threadlocal_aggregate_gt_pivot_1 += probs_gt_pivot_1[j];
      }
    }
    aggregate_gt_pivot_0 +=
        BlockReduce<ValueCount<float>, BLOCK_THREADS>(temp_storage.block_prim.reduce_value_count)
            .Sum(threadlocal_aggregate_gt_pivot_0);
    if (tx == 0) {
      temp_storage.block_aggregate.pair = aggregate_gt_pivot_0;
    }
    __syncthreads();
    aggregate_gt_pivot_0 = temp_storage.block_aggregate.pair;

    aggregate_gt_pivot_1 +=
        BlockReduce<ValueCount<float>, BLOCK_THREADS>(temp_storage.block_prim.reduce_value_count)
            .Sum(threadlocal_aggregate_gt_pivot_1);
    if (tx == 0) {
      temp_storage.block_aggregate.pair = aggregate_gt_pivot_1;
    }
    __syncthreads();
    aggregate_gt_pivot_1 = temp_storage.block_aggregate.pair;
    if (aggregate_gt_pivot_0.count < static_cast<int>(k) && aggregate_gt_pivot_0.value < p) {
      break;
    }
    if (aggregate_gt_pivot_1.count < static_cast<int>(k) && aggregate_gt_pivot_1.value < p) {
      low = pivot_0;
      high = pivot_1;
      q = aggregate_gt_pivot_0.value;
    } else {
      low = pivot_1;
      q = aggregate_gt_pivot_1.value;
    }
  } while (low < high);
  __syncthreads();
  if (tx == 0) {
    output[bx] = sampled_id;
  }
}

// -------------------------------- Launcher wrappers --------------------------------

template <typename T, typename IdType>
static void TopKSamplingFromProb(T* probs, IdType* output, IdType* indices, IdType* top_k_arr,
                                 uint32_t batch_size, uint32_t top_k_val, uint32_t d,
                                 bool deterministic, uint64_t philox_seed, uint64_t philox_offset,
                                 hipStream_t stream) {
  constexpr int VEC_SIZE = 16 / sizeof(T);
  dim3 nblks(batch_size);
  DISPATCH_BLOCK_THREADS(batch_size, THREADS, {
    const uint32_t smem_size = sizeof(SamplingTempStorage<THREADS, SCAN_ALGO, REDUCE_ALGO>);
    dim3 nthrs(THREADS);
    DISPATCH_DETERMINISTIC(deterministic, DETERMINISTIC, {
      auto kernel = TopKSamplingFromProbKernel<THREADS, SCAN_ALGO, REDUCE_ALGO, VEC_SIZE,
                                               DETERMINISTIC, T, IdType>;
      kernel<<<nblks, nthrs, smem_size, stream>>>(probs, output, indices, top_k_arr, top_k_val, d,
                                                  philox_seed, philox_offset);
    });
  });
}

template <typename T, typename IdType>
static void TopPSamplingFromProb(T* probs, IdType* output, IdType* indices, T* top_p_arr,
                                 uint32_t batch_size, T top_p_val, uint32_t d, bool deterministic,
                                 uint64_t philox_seed, uint64_t philox_offset, hipStream_t stream) {
  constexpr int VEC_SIZE = 16 / sizeof(T);
  dim3 nblks(batch_size);
  DISPATCH_BLOCK_THREADS(batch_size, THREADS, {
    const uint32_t smem_size = sizeof(SamplingTempStorage<THREADS, SCAN_ALGO, REDUCE_ALGO>);
    dim3 nthrs(THREADS);
    DISPATCH_DETERMINISTIC(deterministic, DETERMINISTIC, {
      auto kernel = TopPSamplingFromProbKernel<THREADS, SCAN_ALGO, REDUCE_ALGO, VEC_SIZE,
                                               DETERMINISTIC, T, IdType>;
      kernel<<<nblks, nthrs, smem_size, stream>>>(probs, output, indices, top_p_arr, top_p_val, d,
                                                  philox_seed, philox_offset);
    });
  });
}

template <typename T, typename IdType>
static void TopKTopPSamplingFromProb(T* probs, IdType* top_k_arr, T* top_p_arr, IdType* output,
                                     IdType* indices, uint32_t batch_size, IdType top_k_val,
                                     T top_p_val, uint32_t d, bool deterministic,
                                     uint64_t philox_seed, uint64_t philox_offset,
                                     hipStream_t stream) {
  constexpr int VEC_SIZE = 16 / sizeof(T);
  dim3 nblks(batch_size);
  DISPATCH_BLOCK_THREADS(batch_size, THREADS, {
    const uint32_t smem_size = sizeof(SamplingTempStorage<THREADS, SCAN_ALGO, REDUCE_ALGO>);
    dim3 nthrs(THREADS);
    DISPATCH_DETERMINISTIC(deterministic, DETERMINISTIC, {
      auto kernel = TopKTopPSamplingFromProbKernel<THREADS, SCAN_ALGO, REDUCE_ALGO, VEC_SIZE,
                                                   DETERMINISTIC, T, IdType>;
      kernel<<<nblks, nthrs, smem_size, stream>>>(probs, top_k_arr, top_p_arr, output, indices,
                                                  top_k_val, top_p_val, d,
                                                  philox_seed, philox_offset);
    });
  });
}

// -------------------------------- Public entry points --------------------------------

void c_top_k_sampling_from_probs(const torch::Tensor& probs, torch::Tensor& output,
                               std::optional<torch::Tensor> maybe_indices,
                               std::optional<torch::Tensor> maybe_top_k_arr, int64_t top_k_val,
                               bool deterministic, int64_t philox_seed, int64_t philox_offset) {
  unsigned int batch_size = output.size(0);
  unsigned int vocab_size = probs.size(1);
  bool has_top_k_arr = maybe_top_k_arr.has_value();

  using IdType = int;
  hipStream_t stream = at::cuda::getCurrentHIPStream();

  TopKSamplingFromProb<float, IdType>(
      static_cast<float*>(probs.data_ptr()), static_cast<IdType*>(output.data_ptr()),
      maybe_indices.has_value() ? static_cast<IdType*>(maybe_indices.value().data_ptr()) : nullptr,
      has_top_k_arr ? static_cast<IdType*>(maybe_top_k_arr.value().data_ptr()) : nullptr,
      batch_size, static_cast<uint32_t>(top_k_val), vocab_size, deterministic,
      static_cast<uint64_t>(philox_seed), static_cast<uint64_t>(philox_offset), stream);
}

void c_top_p_sampling_from_probs(const torch::Tensor& probs, torch::Tensor& output,
                               std::optional<torch::Tensor> maybe_indices,
                               std::optional<torch::Tensor> maybe_top_p_arr, double top_p_val,
                               bool deterministic, int64_t philox_seed, int64_t philox_offset) {
  unsigned int batch_size = output.size(0);
  unsigned int vocab_size = probs.size(1);
  bool has_top_p_arr = maybe_top_p_arr.has_value();

  using IdType = int;
  hipStream_t stream = at::cuda::getCurrentHIPStream();

  TopPSamplingFromProb<float, IdType>(
      static_cast<float*>(probs.data_ptr()), static_cast<IdType*>(output.data_ptr()),
      maybe_indices.has_value() ? static_cast<IdType*>(maybe_indices.value().data_ptr()) : nullptr,
      has_top_p_arr ? static_cast<float*>(maybe_top_p_arr.value().data_ptr()) : nullptr,
      batch_size, static_cast<float>(top_p_val), vocab_size, deterministic,
      static_cast<uint64_t>(philox_seed), static_cast<uint64_t>(philox_offset), stream);
}

void c_top_k_top_p_sampling_from_probs(const torch::Tensor& probs, torch::Tensor& output,
                                     std::optional<torch::Tensor> maybe_indices,
                                     std::optional<torch::Tensor> maybe_top_k_arr,
                                     int64_t top_k_val,
                                     std::optional<torch::Tensor> maybe_top_p_arr,
                                     double top_p_val, bool deterministic, int64_t philox_seed,
                                     int64_t philox_offset) {
  unsigned int batch_size = output.size(0);
  unsigned int vocab_size = probs.size(1);
  bool has_top_k_arr = maybe_top_k_arr.has_value();
  bool has_top_p_arr = maybe_top_p_arr.has_value();

  using IdType = int;
  hipStream_t stream = at::cuda::getCurrentHIPStream();

  TopKTopPSamplingFromProb<float, IdType>(
      static_cast<float*>(probs.data_ptr()),
      has_top_k_arr ? static_cast<IdType*>(maybe_top_k_arr.value().data_ptr()) : nullptr,
      has_top_p_arr ? static_cast<float*>(maybe_top_p_arr.value().data_ptr()) : nullptr,
      static_cast<IdType*>(output.data_ptr()),
      maybe_indices.has_value() ? static_cast<IdType*>(maybe_indices.value().data_ptr()) : nullptr,
      batch_size, static_cast<IdType>(top_k_val), static_cast<float>(top_p_val), vocab_size,
      deterministic, static_cast<uint64_t>(philox_seed), static_cast<uint64_t>(philox_offset),
      stream);
}

#undef DCU_WARP_SIZE
#undef __INLINE__
#undef DISPATCH_DETERMINISTIC
#undef DISPATCH_BLOCK_THREADS

} // namespace sampling
} // namespace aiter
