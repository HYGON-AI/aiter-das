#include <ATen/hip/HIPContext.h>
#include <ATen/hip/impl/HIPGuardImplMasqueradingAsCUDA.h>
#include <c10/macros/Macros.h>
#include <torch/extension.h>

#ifdef USE_ROCM
#include <hip/hip_fp16.h>
#include <hipcub/hipcub.hpp>
#else
#include <cub/cub.cuh>
#endif

#include <cstddef>
#include <cstdint>
#include <cstdlib>
#include <optional>

void kpool_topk_fallback_launcher(
    const at::Tensor& score,
    const at::Tensor& lengths,
    at::Tensor& dst_token_indices,
    int64_t pool_size,
    std::optional<at::Tensor> page_table_opt,
    std::optional<at::Tensor> topk_indices_offset_opt,
    std::optional<at::Tensor> row_starts_opt,
    std::optional<at::Tensor> seq_lens_opt,
    std::optional<at::Tensor> page_table_row_index_opt);

namespace {

#define CHECK_CUDA(x) TORCH_CHECK(x.is_cuda(), #x " must be a CUDA tensor")
#define CHECK_CONTIGUOUS(x) TORCH_CHECK(x.is_contiguous(), #x " must be contiguous")

constexpr int kKpoolTopkBlockThreads16 = 512;
constexpr int kKpoolTopkBlockThreads4 = 512;
constexpr int kKpoolTopkTokenTopK = 2048;
constexpr int kKpoolTopkPoolSize16 = 16;
constexpr int kKpoolTopkGroupTopK128 = 128;
constexpr int kKpoolTopkPoolSize4 = 4;
constexpr int kKpoolTopkGroupTopK512 = 512;
constexpr int kKpoolTopkSlotCache16 = 8;
constexpr int kKpoolTopkSlotCache4 = 44;
constexpr int kKpoolTopkFinalItems16 = 1024;
constexpr int kKpoolTopkFinalItems4 = 2048;

bool force_fallback() {
  const char* value = std::getenv("SGL_KERNEL_KPOOL_TOPK_FORCE_FALLBACK");
  return value != nullptr && value[0] != '\0' && value[0] != '0';
}

bool sort_writeback_enabled() {
  const char* value = std::getenv("SGL_KERNEL_KPOOL_TOPK_SORT_WRITEBACK");
  return value != nullptr && value[0] != '\0' && value[0] != '0';
}

bool supports_optimized_path(int64_t pool_size, int64_t group_topk) {
  if (pool_size == 16 && group_topk == 128) {
    return true;
  }
  if (pool_size == 4 && group_topk == 512) {
    return true;
  }
  return false;
}

struct KpoolTopkRowInfo {
  int row_start;
  int length;
  int history_len;
  int tail_count;
  int tail_start;
  int page_row;
  int32_t ragged_offset;
};

template <int PoolSize, int GroupTopK>
__device__ __forceinline__ KpoolTopkRowInfo load_row_info(
    int row,
    int score_cols,
    const int32_t* __restrict__ lengths,
    const int32_t* __restrict__ row_starts,
    const int32_t* __restrict__ seq_lens,
    const int32_t* __restrict__ page_table_row_index,
    const int32_t* __restrict__ topk_indices_offset) {
  int row_start = row_starts == nullptr ? 0 : row_starts[row];
  row_start = row_start < 0 ? 0 : row_start;

  const int max_length = score_cols > row_start ? score_cols - row_start : 0;
  int length = lengths[row];
  length = length < 0 ? 0 : (length < max_length ? length : max_length);

  const int history_groups = length < GroupTopK ? length : GroupTopK;
  KpoolTopkRowInfo info;
  info.row_start = row_start;
  info.length = length;
  info.history_len = history_groups * PoolSize;
  info.tail_count = seq_lens == nullptr ? 0 : (seq_lens[row] % PoolSize);
  info.tail_start = length * PoolSize;
  info.page_row = page_table_row_index == nullptr ? row : page_table_row_index[row];
  info.ragged_offset = topk_indices_offset == nullptr ? 0 : topk_indices_offset[row];
  return info;
}

template <int GroupTopK>
__device__ __forceinline__ void sort_selected_groups_by_id(
    int* __restrict__ group_ids,
    int* __restrict__ sorted_group_ids) {
  const int tid = threadIdx.x;
  static_assert((GroupTopK & (GroupTopK - 1)) == 0);

  if constexpr (GroupTopK == kKpoolTopkGroupTopK128) {
    const int lane = tid & 63;
    const int wave = tid >> 6;
    if (wave < 2) {
      int value = group_ids[tid];
#pragma unroll
      for (int k = 2; k <= 64; k <<= 1) {
#pragma unroll
        for (int j = k >> 1; j > 0; j >>= 1) {
          const int peer = __shfl_xor(value, j, 64);
          const bool lower_lane = (lane & j) == 0;
          const bool ascending = (lane & k) == 0;
          const bool keep_min = lower_lane == ascending;
          value = keep_min ? (value < peer ? value : peer) : (value > peer ? value : peer);
        }
      }
      sorted_group_ids[tid] = value;
    }
    __syncthreads();

    if (tid < GroupTopK) {
      const int value = sorted_group_ids[tid];
      const int* other = sorted_group_ids + ((tid < 64) ? 64 : 0);
      int lo = 0;
      int hi = 64;
      while (lo < hi) {
        const int mid = (lo + hi) >> 1;
        if (other[mid] < value) {
          lo = mid + 1;
        } else {
          hi = mid;
        }
      }
      group_ids[(tid & 63) + lo] = value;
    }
    __syncthreads();
  } else {
    if (tid < GroupTopK) {
      sorted_group_ids[tid] = group_ids[tid];
    }
    __syncthreads();

    int* src = sorted_group_ids;
    int* dst = group_ids;
    if (tid < GroupTopK) {
      for (int k = 2; k <= GroupTopK; k <<= 1) {
        const bool ascending = (tid & k) == 0;
        for (int j = k >> 1; j > 0; j >>= 1) {
          const int value = src[tid];
          const int peer = src[tid ^ j];
          const bool lower_lane = (tid & j) == 0;
          const bool keep_min = lower_lane == ascending;
          dst[tid] = keep_min ? (value < peer ? value : peer) : (value > peer ? value : peer);
          __syncthreads();
          int* tmp = src;
          src = dst;
          dst = tmp;
        }
      }
      if (src != group_ids) {
        group_ids[tid] = src[tid];
      }
    } else {
      for (int k = 2; k <= GroupTopK; k <<= 1) {
        for (int j = k >> 1; j > 0; j >>= 1) {
          __syncthreads();
          int* tmp = src;
          src = dst;
          dst = tmp;
        }
      }
    }
    __syncthreads();
  }
}

template <typename T, typename IdxT, typename Func>
__device__ __forceinline__ void fast_kpool_topk_vectorized_process(
    int thread_rank,
    int num_threads,
    const T* __restrict__ in,
    IdxT len,
    Func f) {
  using WideT = float4;
  if constexpr (sizeof(T) >= sizeof(WideT)) {
    for (IdxT i = thread_rank; i < len; i += num_threads) {
      f(in[i], i);
    }
  } else {
    constexpr int items_per_scalar = sizeof(WideT) / sizeof(T);
    union {
      WideT scalar;
      T array[items_per_scalar];
    } wide;

    int skip_count = (reinterpret_cast<uintptr_t>(in) & (sizeof(WideT) - 1))
        ? static_cast<int>((sizeof(WideT) - (reinterpret_cast<uintptr_t>(in) & (sizeof(WideT) - 1))) /
                           sizeof(T))
        : 0;
    if (skip_count > len) {
      skip_count = len;
    }

    const WideT* __restrict__ in_vec = reinterpret_cast<const WideT*>(in + skip_count);
    const IdxT vec_count = (len - skip_count) / items_per_scalar;
    for (IdxT vec = thread_rank; vec < vec_count; vec += num_threads) {
      wide.scalar = in_vec[vec];
      const IdxT base = skip_count + vec * items_per_scalar;
#pragma unroll
      for (int item = 0; item < items_per_scalar; ++item) {
        f(wide.array[item], base + item);
      }
    }

    if (thread_rank < skip_count) {
      f(in[thread_rank], thread_rank);
    }
    const IdxT tail = skip_count + vec_count * items_per_scalar + thread_rank;
    if (tail < len) {
      f(in[tail], tail);
    }
  }
}

template <typename T, typename IdxT, typename Func>
__device__ __forceinline__ void fast_kpool_topk_vectorized_write(
    int thread_rank,
    int num_threads,
    T* __restrict__ out,
    IdxT len,
    Func f) {
  using WideT = float4;
  if constexpr (sizeof(T) >= sizeof(WideT)) {
    for (IdxT i = thread_rank; i < len; i += num_threads) {
      out[i] = f(i);
    }
  } else {
    constexpr int items_per_scalar = sizeof(WideT) / sizeof(T);
    union {
      WideT scalar;
      T array[items_per_scalar];
    } wide;

    int skip_count = (reinterpret_cast<uintptr_t>(out) & (sizeof(WideT) - 1))
        ? static_cast<int>((sizeof(WideT) - (reinterpret_cast<uintptr_t>(out) & (sizeof(WideT) - 1))) /
                           sizeof(T))
        : 0;
    if (skip_count > len) {
      skip_count = len;
    }

    if (thread_rank < skip_count) {
      out[thread_rank] = f(thread_rank);
    }

    WideT* __restrict__ out_vec = reinterpret_cast<WideT*>(out + skip_count);
    const IdxT vec_count = (len - skip_count) / items_per_scalar;
    for (IdxT vec = thread_rank; vec < vec_count; vec += num_threads) {
      const IdxT base = skip_count + vec * items_per_scalar;
#pragma unroll
      for (int item = 0; item < items_per_scalar; ++item) {
        wide.array[item] = f(base + item);
      }
      out_vec[vec] = wide.scalar;
    }

    const IdxT tail = skip_count + vec_count * items_per_scalar + thread_rank;
    if (tail < len) {
      out[tail] = f(tail);
    }
  }
}

__device__ __forceinline__ uint32_t fast_kpool_topk_score_key(float x) {
  uint32_t bits = __float_as_uint(x);
  return (bits & 0x80000000u) ? bits : (~bits & 0x7fffffffu);
}

template <int Step, int CoarseShift>
__device__ __forceinline__ uint32_t fast_kpool_topk_extract_bin(float x) {
  if constexpr (Step == 0) {
    __half hx = __float2half(x);
    uint16_t bits = __half_as_ushort(hx);
    bits = (bits & 0x8000u) ? bits : static_cast<uint16_t>(~bits & 0x7fffu);
    return bits >> CoarseShift;
  } else {
    uint32_t bits = fast_kpool_topk_score_key(x);
    if constexpr (Step == 1) {
      return bits >> 21;
    } else if constexpr (Step == 2) {
      return (bits >> 10) & 0x7ffu;
    } else {
      return bits & 0x3ffu;
    }
  }
}

template <int Shift>
__device__ __forceinline__ bool fast_kpool_topk_partial_match(float x, uint32_t pattern) {
  if constexpr (Shift == 0) {
    return true;
  }
  const uint32_t bits = fast_kpool_topk_score_key(x);
  return ((bits ^ pattern) >> Shift) == 0;
}

template <int BlockThreads, typename SmemFinalType>
__device__ __forceinline__ void write_ranked_final_candidates(
    SmemFinalType& smem_final,
    int final_count,
    int base,
    int* __restrict__ smem_output,
    int topk) {
  const int tx = threadIdx.x;
  for (int i = tx; i < final_count; i += BlockThreads) {
    int out_rank = 0;
    const float score = smem_final.items.logits[i];
    const uint32_t key = fast_kpool_topk_score_key(score);
    for (int j = 0; j < final_count; ++j) {
      const float other_score = smem_final.items.logits[j];
      const uint32_t other_key = fast_kpool_topk_score_key(other_score);
      if (key > other_key || (key == other_key && i > j)) {
        ++out_rank;
      }
    }
    if (base + out_rank < topk) {
      smem_output[base + out_rank] = smem_final.items.indices[i];
    }
  }
  __syncthreads();
}

template <typename SmemFinalType>
struct FastKpoolTopkStepState {
  const float* __restrict__ row_score;
  int row_start;
  int row_end;
  uint32_t* __restrict__ score_pattern;
  int* __restrict__ threshold_bin;
  int* __restrict__ smem_output;
  int* __restrict__ smem_threshold_bin;
  int* __restrict__ smem_final_bin_size;
  int* __restrict__ smem_found_topk;
  SmemFinalType* __restrict__ smem_final;
  int topk;
  float* __restrict__ slot_raw;
  bool use_slot_cache;
  int row_len;
};

template <
    int Step,
    int BlockThreads,
    int NumBins,
    int NumFinalItems,
    int SlotCache,
    int CoarseShift,
    bool EnableSlotCache,
    typename SmemFinalType>
__device__ bool fast_kpool_topk_histogram_step(
    FastKpoolTopkStepState<SmemFinalType> state) {
  const int tx = threadIdx.x;
  const float* __restrict__ row_score = state.row_score;
  const int row_start = state.row_start;
  uint32_t& score_pattern = *state.score_pattern;
  int& threshold_bin = *state.threshold_bin;
  int* __restrict__ smem_output = state.smem_output;
  int* __restrict__ smem_threshold_bin = state.smem_threshold_bin;
  int* __restrict__ smem_final_bin_size = state.smem_final_bin_size;
  int* __restrict__ smem_found_topk = state.smem_found_topk;
  SmemFinalType& smem_final = *state.smem_final;
  const int topk = state.topk;
  float* __restrict__ slot_raw = state.slot_raw;
  const bool use_slot_cache = state.use_slot_cache;
  const int row_len = state.row_len;
  uint32_t slot_bins[SlotCache];

  for (int idx = tx; idx < NumBins; idx += BlockThreads) {
    smem_final.histo.data[idx] = 0;
  }
  __syncthreads();

  constexpr int pattern_shift = Step < 2 ? 0 : Step == 2 ? 21 : 10;
  if constexpr (Step == 2) {
    score_pattern = static_cast<uint32_t>(threshold_bin & 0x7ff) << pattern_shift;
  } else if constexpr (Step == 3) {
    score_pattern |= static_cast<uint32_t>(threshold_bin & 0x7ff) << pattern_shift;
  }

  auto count_bin = [&](float score, int /*idx*/) {
    if (fast_kpool_topk_partial_match<pattern_shift>(score, score_pattern)) {
      const uint32_t bin = fast_kpool_topk_extract_bin<Step, CoarseShift>(score);
      atomicAdd(&smem_final.histo.data[bin], 1);
    }
  };

  if constexpr (EnableSlotCache) {
    if (use_slot_cache) {
#pragma unroll
      for (int slot = 0; slot < SlotCache; ++slot) {
        const int idx = tx + slot * BlockThreads;
        if (idx < row_len) {
          if constexpr (Step == 0) {
            const uint32_t bin = fast_kpool_topk_extract_bin<Step, CoarseShift>(slot_raw[slot]);
            slot_bins[slot] = bin;
            atomicAdd(&smem_final.histo.data[bin], 1);
          } else {
            count_bin(slot_raw[slot], idx);
          }
        }
      }
    } else {
      fast_kpool_topk_vectorized_process(tx, BlockThreads, row_score + row_start, row_len, count_bin);
    }
  } else {
    fast_kpool_topk_vectorized_process(tx, BlockThreads, row_score + row_start, row_len, count_bin);
  }
  __syncthreads();

  const int last_value = smem_found_topk[0];
  constexpr int ItemsPerThread = NumBins / BlockThreads;
  int bin_data[ItemsPerThread];
#pragma unroll
  for (int i = 0; i < ItemsPerThread; ++i) {
    bin_data[i] = smem_final.histo.data[tx * ItemsPerThread + i];
  }

  int prefix_sums[ItemsPerThread];
  int total_sum = 0;
#ifdef USE_ROCM
  using Scan = hipcub::BlockScan<int, BlockThreads>;
#else
  using Scan = cub::BlockScan<int, BlockThreads>;
#endif
  Scan(smem_final.histo.scan).ExclusiveSum(bin_data, prefix_sums, total_sum);

#pragma unroll
  for (int i = 0; i < ItemsPerThread; ++i) {
    prefix_sums[i] += last_value;
    smem_final.histo.data[tx * ItemsPerThread + i] = prefix_sums[i];
  }
  __syncthreads();

#pragma unroll
  for (int i = 0; i < ItemsPerThread; ++i) {
    const int idx = tx * ItemsPerThread + i;
    const int prefix = prefix_sums[i];
    if (prefix < topk) {
      const int next_prefix =
          idx == NumBins - 1 ? total_sum + last_value : smem_final.histo.data[idx + 1];
      if (next_prefix >= topk) {
        smem_threshold_bin[0] = idx;
        smem_final_bin_size[0] = next_prefix - prefix;
      }
    }
  }
  __syncthreads();

  threshold_bin = smem_threshold_bin[0];
  const bool collect_final_bin = smem_final_bin_size[0] <= NumFinalItems;
  if (tx == 0 && collect_final_bin) {
    smem_final_bin_size[0] = 0;
  }
  __syncthreads();

  auto collect_bin = [&](float score, int idx) {
    if (fast_kpool_topk_partial_match<pattern_shift>(score, score_pattern)) {
      const uint32_t bin = fast_kpool_topk_extract_bin<Step, CoarseShift>(score);
      if (bin < static_cast<uint32_t>(threshold_bin)) {
        const int dst = atomicAdd(smem_found_topk, 1);
        smem_output[dst] = idx;
      }
      if constexpr (Step < 3) {
        if (bin == static_cast<uint32_t>(threshold_bin) && collect_final_bin) {
          const int dst = atomicAdd(smem_final_bin_size, 1);
          smem_final.items.logits[dst] = score;
          smem_final.items.indices[dst] = idx;
        }
      } else {
        if (bin == static_cast<uint32_t>(threshold_bin)) {
          const int dst = atomicAdd(&smem_final.histo.data[bin], 1);
          if (dst < topk) {
            smem_output[dst] = idx;
          }
        }
      }
    }
  };

  if constexpr (EnableSlotCache) {
    if (use_slot_cache) {
#pragma unroll
      for (int slot = 0; slot < SlotCache; ++slot) {
        const int idx = tx + slot * BlockThreads;
        if (idx < row_len) {
          if constexpr (Step == 0) {
            const uint32_t bin = slot_bins[slot];
            const float score = slot_raw[slot];
            if (bin < static_cast<uint32_t>(threshold_bin)) {
              const int dst = atomicAdd(smem_found_topk, 1);
              smem_output[dst] = idx;
            }
            if (bin == static_cast<uint32_t>(threshold_bin) && collect_final_bin) {
              const int dst = atomicAdd(smem_final_bin_size, 1);
              smem_final.items.logits[dst] = score;
              smem_final.items.indices[dst] = idx;
            }
          } else {
            collect_bin(slot_raw[slot], idx);
          }
        }
      }
    } else {
      fast_kpool_topk_vectorized_process(tx, BlockThreads, row_score + row_start, row_len, collect_bin);
    }
  } else {
    fast_kpool_topk_vectorized_process(tx, BlockThreads, row_score + row_start, row_len, collect_bin);
  }
  __syncthreads();

  return smem_final_bin_size[0] > NumFinalItems;
}

template <
    int BlockThreads,
    int CoarseBins,
    int RefineBins,
    int MaxTopK,
    int SlotCache,
    int CoarseShift,
    bool EnableSlotCache>
__device__ void fast_kpool_topk_topk_groups(
    const float* __restrict__ row_score,
    int row_start,
    int row_end,
    int* __restrict__ out_indices,
    int topk) {
  constexpr int NumFinalItems = MaxTopK;
  static_assert(CoarseBins % BlockThreads == 0);
  static_assert(RefineBins % BlockThreads == 0);

#ifdef USE_ROCM
  using Scan = hipcub::BlockScan<int, BlockThreads>;
#else
  using Scan = cub::BlockScan<int, BlockThreads>;
#endif
  struct FinalItems {
    int indices[NumFinalItems];
    float logits[NumFinalItems];
  };
  struct Histogram {
    typename Scan::TempStorage scan;
    int data[CoarseBins > RefineBins ? CoarseBins : RefineBins];
  };
  __shared__ union {
    FinalItems items;
    Histogram histo;
  } smem_final;
  __shared__ int smem_threshold_bin[1];
  __shared__ int smem_final_bin_size[1];
  __shared__ int smem_found_topk[1];
  int* __restrict__ smem_output = out_indices;

  const int tx = threadIdx.x;
  const int row_len = row_end - row_start;
  if (row_len <= topk) {
    fast_kpool_topk_vectorized_write<int, int>(
        tx, BlockThreads, out_indices, topk, [row_len] __device__(int i) {
          return i < row_len ? i : -1;
        });
    return;
  }

  float slot_raw[SlotCache];
  const bool use_slot_cache = EnableSlotCache && row_len <= SlotCache * BlockThreads;
  if constexpr (EnableSlotCache) {
    if (use_slot_cache) {
#pragma unroll
      for (int slot = 0; slot < SlotCache; ++slot) {
        const int idx = tx + slot * BlockThreads;
        slot_raw[slot] = idx < row_len ? row_score[row_start + idx] : 0.0f;
      }
    }
  }

  fast_kpool_topk_vectorized_write<int, int>(
      tx, BlockThreads, smem_output, topk, [] __device__(int) { return -1; });

  if (tx == 0) {
    smem_found_topk[0] = 0;
  }
  __syncthreads();

  int threshold_bin = -1;
  uint32_t score_pattern = 0;
  FastKpoolTopkStepState<decltype(smem_final)> step_state{
      row_score,
      row_start,
      row_end,
      &score_pattern,
      &threshold_bin,
      smem_output,
      smem_threshold_bin,
      smem_final_bin_size,
      smem_found_topk,
      &smem_final,
      topk,
      slot_raw,
      use_slot_cache,
      row_len};
  bool refine = fast_kpool_topk_histogram_step<
      0,
      BlockThreads,
      CoarseBins,
      NumFinalItems,
      SlotCache,
      CoarseShift,
      EnableSlotCache>(
      step_state);
  if (refine) {
    refine = fast_kpool_topk_histogram_step<
        1,
        BlockThreads,
        RefineBins,
        NumFinalItems,
        SlotCache,
        CoarseShift,
        EnableSlotCache>(
        step_state);
  }
  if (refine) {
    refine = fast_kpool_topk_histogram_step<
        2,
        BlockThreads,
        RefineBins,
        NumFinalItems,
        SlotCache,
        CoarseShift,
        EnableSlotCache>(
        step_state);
  }
  if (refine) {
    fast_kpool_topk_histogram_step<
        3,
        BlockThreads,
        RefineBins / 2,
        NumFinalItems,
        SlotCache,
        CoarseShift,
        EnableSlotCache>(
        step_state);
  }

  if (!refine) {
    write_ranked_final_candidates<BlockThreads>(
        smem_final,
        smem_final_bin_size[0],
        smem_found_topk[0],
        smem_output,
        topk);
  }

  __syncthreads();
}

template <int BlockThreads, int GroupTopK>
__device__ __forceinline__ void select_topk_groups(
    const float* __restrict__ row_score,
    const KpoolTopkRowInfo& row,
    int32_t* __restrict__ selected_groups) {
  if (row.length <= GroupTopK) {
    fast_kpool_topk_vectorized_write<int32_t, int>(
        threadIdx.x,
        BlockThreads,
        selected_groups,
        GroupTopK,
        [length = row.length] __device__(int i) { return i < length ? i : -1; });
  } else {
    if constexpr (GroupTopK == kKpoolTopkGroupTopK128) {
      fast_kpool_topk_topk_groups<
          BlockThreads,
          2048,
          2048,
          kKpoolTopkFinalItems16,
          kKpoolTopkSlotCache16,
          5,
          true>(
          row_score,
          row.row_start,
          row.row_start + row.length,
          selected_groups,
          GroupTopK);
    } else {
      fast_kpool_topk_topk_groups<
          BlockThreads,
          4096,
          2048,
          kKpoolTopkFinalItems4,
          kKpoolTopkSlotCache4,
          4,
          true>(
          row_score,
          row.row_start,
          row.row_start + row.length,
          selected_groups,
          GroupTopK);
    }
  }
  __syncthreads();
}

template <bool SortWriteback, int GroupTopK>
__device__ __forceinline__ void maybe_sort_selected_groups(
    int32_t* __restrict__ selected_groups,
    bool can_sort,
    int length) {
  if constexpr (SortWriteback) {
    if (can_sort && length > GroupTopK) {
      __shared__ int32_t sorted_groups[GroupTopK];
      sort_selected_groups_by_id<GroupTopK>(selected_groups, sorted_groups);
    }
  }
}

__device__ __forceinline__ int32_t fast_kpool_topk_transform_token(
    int raw_token,
    const int32_t* __restrict__ page_table,
    int64_t page_table_stride,
    int64_t page_table_rows,
    int64_t page_table_cols,
    int page_row,
    int32_t ragged_offset) {
  if (raw_token < 0) {
    return -1;
  }
  if (page_table != nullptr) {
    if (page_row < 0 || page_row >= page_table_rows || raw_token >= page_table_cols) {
      return -1;
    }
    return page_table[static_cast<int64_t>(page_row) * page_table_stride + raw_token];
  }
  return raw_token + ragged_offset;
}

template <int PoolSize>
__device__ __forceinline__ int32_t fast_kpool_topk_output_value(
    int col,
    const int32_t* __restrict__ selected_groups,
    int history_len,
    int tail_count,
    int tail_start,
    const int32_t* __restrict__ page_table,
    int64_t page_table_stride,
    int64_t page_table_rows,
    int64_t page_table_cols,
    int page_row,
    int32_t ragged_offset) {
  int raw_token = -1;
  if (col < history_len) {
    const int group_rank = col / PoolSize;
    const int group_offset = col % PoolSize;
    const int group_id = selected_groups[group_rank];
    raw_token = group_id >= 0 ? group_id * PoolSize + group_offset : -1;
  } else {
    const int tail_offset = col - history_len;
    if (tail_offset >= 0 && tail_offset < tail_count) {
      raw_token = tail_start + tail_offset;
    }
  }
  return fast_kpool_topk_transform_token(
      raw_token,
      page_table,
      page_table_stride,
      page_table_rows,
      page_table_cols,
      page_row,
      ragged_offset);
}

template <int PoolSize>
__device__ __forceinline__ void fast_kpool_topk_write_output(
    int32_t* __restrict__ dst,
    int out_cols,
    const int32_t* __restrict__ selected_groups,
    int history_len,
    int tail_count,
    int tail_start,
    const int32_t* __restrict__ page_table,
    int64_t page_table_stride,
    int64_t page_table_rows,
    int64_t page_table_cols,
    int page_row,
    int32_t ragged_offset) {
  const int tx = threadIdx.x;
  const uintptr_t dst_addr = reinterpret_cast<uintptr_t>(dst);
  int scalar_prefix = (dst_addr & 0xF) ? static_cast<int>((16 - (dst_addr & 0xF)) >> 2) : 0;
  if (scalar_prefix > out_cols) {
    scalar_prefix = out_cols;
  }

  for (int col = tx; col < scalar_prefix; col += blockDim.x) {
    dst[col] = fast_kpool_topk_output_value<PoolSize>(
        col,
        selected_groups,
        history_len,
        tail_count,
        tail_start,
        page_table,
        page_table_stride,
        page_table_rows,
        page_table_cols,
        page_row,
        ragged_offset);
  }

  int4* __restrict__ dst_vec = reinterpret_cast<int4*>(dst + scalar_prefix);
  const int vec_cols = out_cols - scalar_prefix;
  const int vec_count = vec_cols >> 2;
  for (int vec = tx; vec < vec_count; vec += blockDim.x) {
    const int col = scalar_prefix + (vec << 2);
    int4 value;
    value.x = fast_kpool_topk_output_value<PoolSize>(
        col,
        selected_groups,
        history_len,
        tail_count,
        tail_start,
        page_table,
        page_table_stride,
        page_table_rows,
        page_table_cols,
        page_row,
        ragged_offset);
    value.y = fast_kpool_topk_output_value<PoolSize>(
        col + 1,
        selected_groups,
        history_len,
        tail_count,
        tail_start,
        page_table,
        page_table_stride,
        page_table_rows,
        page_table_cols,
        page_row,
        ragged_offset);
    value.z = fast_kpool_topk_output_value<PoolSize>(
        col + 2,
        selected_groups,
        history_len,
        tail_count,
        tail_start,
        page_table,
        page_table_stride,
        page_table_rows,
        page_table_cols,
        page_row,
        ragged_offset);
    value.w = fast_kpool_topk_output_value<PoolSize>(
        col + 3,
        selected_groups,
        history_len,
        tail_count,
        tail_start,
        page_table,
        page_table_stride,
        page_table_rows,
        page_table_cols,
        page_row,
        ragged_offset);
    dst_vec[vec] = value;
  }

  const int tail_start_col = scalar_prefix + (vec_count << 2);
  for (int col = tail_start_col + tx; col < out_cols; col += blockDim.x) {
    dst[col] = fast_kpool_topk_output_value<PoolSize>(
        col,
        selected_groups,
        history_len,
        tail_count,
        tail_start,
        page_table,
        page_table_stride,
        page_table_rows,
        page_table_cols,
        page_row,
        ragged_offset);
  }
}

__device__ __forceinline__ int4 fast_kpool_topk_make_token4(
    int raw_base,
    const int32_t* __restrict__ page_table,
    int64_t page_table_stride,
    int64_t page_table_rows,
    int64_t page_table_cols,
    int page_row,
    int32_t ragged_offset) {
  int4 value;
  if (raw_base < 0) {
    value.x = -1;
    value.y = -1;
    value.z = -1;
    value.w = -1;
    return value;
  }

  if (page_table != nullptr) {
    if (page_row < 0 || page_row >= page_table_rows || raw_base + 3 >= page_table_cols) {
      value.x = -1;
      value.y = -1;
      value.z = -1;
      value.w = -1;
      return value;
    }
    const int32_t* __restrict__ row_table =
        page_table + static_cast<int64_t>(page_row) * page_table_stride + raw_base;
    if ((reinterpret_cast<uintptr_t>(row_table) & 0xF) == 0) {
      return *reinterpret_cast<const int4*>(row_table);
    }
    value.x = row_table[0];
    value.y = row_table[1];
    value.z = row_table[2];
    value.w = row_table[3];
    return value;
  }

  const int base = raw_base + ragged_offset;
  value.x = base;
  value.y = base + 1;
  value.z = base + 2;
  value.w = base + 3;
  return value;
}

__device__ __forceinline__ void fast_kpool_topk_write_output_pool4(
    int32_t* __restrict__ dst,
    int out_cols,
    const int32_t* __restrict__ selected_groups,
    int history_len,
    int tail_count,
    int tail_start,
    const int32_t* __restrict__ page_table,
    int64_t page_table_stride,
    int64_t page_table_rows,
    int64_t page_table_cols,
    int page_row,
    int32_t ragged_offset) {
  const int tx = threadIdx.x;
  constexpr int PoolSize = 4;
  const int history_groups = history_len / PoolSize;

  if ((reinterpret_cast<uintptr_t>(dst) & 0xF) == 0) {
    int4* __restrict__ dst_vec = reinterpret_cast<int4*>(dst);
    for (int group_rank = tx; group_rank < history_groups; group_rank += blockDim.x) {
      const int group_id = selected_groups[group_rank];
      const int raw_base = group_id >= 0 ? group_id * PoolSize : -1;
      dst_vec[group_rank] = fast_kpool_topk_make_token4(
          raw_base,
          page_table,
          page_table_stride,
          page_table_rows,
          page_table_cols,
          page_row,
          ragged_offset);
    }
  } else {
    for (int col = tx; col < history_len; col += blockDim.x) {
      dst[col] = fast_kpool_topk_output_value<PoolSize>(
          col,
          selected_groups,
          history_len,
          tail_count,
          tail_start,
          page_table,
          page_table_stride,
          page_table_rows,
          page_table_cols,
          page_row,
          ragged_offset);
    }
  }

  for (int col = history_len + tx; col < out_cols; col += blockDim.x) {
    const int tail_offset = col - history_len;
    const int raw_token = tail_offset < tail_count ? tail_start + tail_offset : -1;
    dst[col] = fast_kpool_topk_transform_token(
        raw_token,
        page_table,
        page_table_stride,
        page_table_rows,
        page_table_cols,
        page_row,
        ragged_offset);
  }
}

template <int PoolSize>
__device__ __forceinline__ void write_selected_tokens(
    int32_t* __restrict__ dst,
    int out_cols,
    const int32_t* __restrict__ selected_groups,
    const KpoolTopkRowInfo& row,
    const int32_t* __restrict__ page_table,
    int64_t page_table_stride,
    int64_t page_table_rows,
    int64_t page_table_cols) {
  if constexpr (PoolSize == 4) {
    fast_kpool_topk_write_output_pool4(
        dst,
        out_cols,
        selected_groups,
        row.history_len,
        row.tail_count,
        row.tail_start,
        page_table,
        page_table_stride,
        page_table_rows,
        page_table_cols,
        row.page_row,
        row.ragged_offset);
  } else {
    fast_kpool_topk_write_output<PoolSize>(
        dst,
        out_cols,
        selected_groups,
        row.history_len,
        row.tail_count,
        row.tail_start,
        page_table,
        page_table_stride,
        page_table_rows,
        page_table_cols,
        row.page_row,
        row.ragged_offset);
  }
}

template <int BlockThreads, bool SortWriteback, int PoolSize, int GroupTopK>
__global__ __launch_bounds__(BlockThreads) void kpool_topk_kernel(
    const float* __restrict__ score,
    const int32_t* __restrict__ lengths,
    int32_t* __restrict__ out,
    int64_t score_stride,
    int64_t out_stride,
    int32_t real_rows,
    int32_t out_rows,
    int32_t score_cols,
    int32_t out_cols,
    const int32_t* __restrict__ page_table,
    int64_t page_table_stride,
    int64_t page_table_rows,
    int64_t page_table_cols,
    const int32_t* __restrict__ page_table_row_index,
    const int32_t* __restrict__ topk_indices_offset,
    const int32_t* __restrict__ row_starts,
    const int32_t* __restrict__ seq_lens) {
  const int row = blockIdx.x;
  if (row >= out_rows) {
    return;
  }

  int32_t* dst = out + static_cast<int64_t>(row) * out_stride;
  if (row >= real_rows) {
    for (int col = threadIdx.x; col < out_cols; col += blockDim.x) {
      dst[col] = -1;
    }
    return;
  }

  const KpoolTopkRowInfo row_info = load_row_info<PoolSize, GroupTopK>(
      row, score_cols, lengths, row_starts, seq_lens, page_table_row_index, topk_indices_offset);
  const float* row_score = score + static_cast<int64_t>(row) * score_stride;

  __shared__ int32_t selected_groups[GroupTopK];
  select_topk_groups<BlockThreads, GroupTopK>(row_score, row_info, selected_groups);
  maybe_sort_selected_groups<SortWriteback, GroupTopK>(selected_groups, page_table == nullptr, row_info.length);
  write_selected_tokens<PoolSize>(
      dst,
      out_cols,
      selected_groups,
      row_info,
      page_table,
      page_table_stride,
      page_table_rows,
      page_table_cols);
}

template <auto* f, size_t max_dynamic_smem>
void setup_kernel_smem_once() {
  [[maybe_unused]]
  static const auto result = [] {
#ifdef USE_ROCM
    return ::cudaFuncSetAttribute(
        reinterpret_cast<const void*>(f), ::cudaFuncAttributeMaxDynamicSharedMemorySize, max_dynamic_smem);
#else
    return ::cudaFuncSetAttribute(f, ::cudaFuncAttributeMaxDynamicSharedMemorySize, max_dynamic_smem);
#endif
  }();
  TORCH_CHECK(result == cudaSuccess, "set_up_kernel_once failed:", ::cudaGetErrorString(result));
}

template <int BlockThreads, bool SortWriteback, int PoolSize, int GroupTopK>
void launch_kpool_topk(
    const at::Tensor& score,
    const at::Tensor& lengths,
    at::Tensor& out,
    const int32_t* page_table,
    int64_t page_table_stride,
    int64_t page_table_rows,
    int64_t page_table_cols,
    const int32_t* page_table_row_index,
    const int32_t* offsets,
    const int32_t* row_starts,
    const int32_t* seq_lens) {
  dim3 block(BlockThreads);
  dim3 grid(out.size(0));
  auto stream = at::cuda::getCurrentCUDAStream(score.get_device());
  constexpr size_t dynamic_smem = 0;
  setup_kernel_smem_once<kpool_topk_kernel<BlockThreads, SortWriteback, PoolSize, GroupTopK>, dynamic_smem>();
  kpool_topk_kernel<BlockThreads, SortWriteback, PoolSize, GroupTopK><<<grid, block, dynamic_smem, stream>>>(
      score.data_ptr<float>(),
      lengths.data_ptr<int32_t>(),
      out.data_ptr<int32_t>(),
      score.stride(0),
      out.stride(0),
      static_cast<int32_t>(score.size(0)),
      static_cast<int32_t>(out.size(0)),
      static_cast<int32_t>(score.size(1)),
      static_cast<int32_t>(out.size(1)),
      page_table,
      page_table_stride,
      page_table_rows,
      page_table_cols,
      page_table_row_index,
      offsets,
      row_starts,
      seq_lens);
}

}  // namespace

void kpool_topk_launcher(
    const at::Tensor& score,
    const at::Tensor& lengths,
    at::Tensor& out,
    int64_t pool_size,
    int64_t topk,
    std::optional<at::Tensor> page_table,
    std::optional<at::Tensor> topk_indices_offset,
    std::optional<at::Tensor> row_starts,
    std::optional<at::Tensor> seq_lens,
    std::optional<at::Tensor> page_table_row_index) {
  CHECK_CUDA(score);
  CHECK_CUDA(lengths);
  CHECK_CUDA(out);
  CHECK_CONTIGUOUS(lengths);
  CHECK_CONTIGUOUS(out);
  TORCH_CHECK(score.dim() == 2 && score.stride(1) == 1);
  TORCH_CHECK(lengths.dim() == 1 && lengths.size(0) == score.size(0));
  TORCH_CHECK(out.dim() == 2 && out.size(0) >= score.size(0));
  TORCH_CHECK(score.scalar_type() == at::ScalarType::Float);
  TORCH_CHECK(lengths.scalar_type() == at::ScalarType::Int);
  TORCH_CHECK(out.scalar_type() == at::ScalarType::Int);
  TORCH_CHECK(pool_size > 1, "kpool topk requires pool_size > 1");
  TORCH_CHECK(topk % pool_size == 0);
  TORCH_CHECK(!page_table.has_value() || !topk_indices_offset.has_value());
  TORCH_CHECK(!page_table_row_index.has_value() || page_table.has_value());

  const int64_t group_topk = topk / pool_size;
  TORCH_CHECK(
      group_topk == 64 || group_topk == 128 || group_topk == 160 || group_topk == 192 ||
          group_topk == 224 || group_topk == 256 || group_topk == 512,
      "kpool topk supports group_topk in {64,128,160,192,224,256,512}");
  if (force_fallback() || !supports_optimized_path(pool_size, group_topk)) {
    kpool_topk_fallback_launcher(
        score, lengths, out, pool_size, page_table, topk_indices_offset, row_starts, seq_lens, page_table_row_index);
    return;
  }

  const int32_t* page_table_ptr = nullptr;
  int64_t page_table_stride = 0;
  if (page_table.has_value()) {
    CHECK_CUDA(page_table.value());
    TORCH_CHECK(page_table->dim() == 2 && page_table->stride(1) == 1);
    TORCH_CHECK(page_table->scalar_type() == at::ScalarType::Int);
    if (!page_table_row_index.has_value()) {
      TORCH_CHECK(page_table->size(0) == score.size(0));
    }
    page_table_ptr = page_table->data_ptr<int32_t>();
    page_table_stride = page_table->stride(0);
  }
  const int32_t* page_table_row_index_ptr = nullptr;
  if (page_table_row_index.has_value()) {
    CHECK_CUDA(page_table_row_index.value());
    CHECK_CONTIGUOUS(page_table_row_index.value());
    TORCH_CHECK(page_table_row_index->dim() == 1);
    TORCH_CHECK(page_table_row_index->size(0) == score.size(0));
    TORCH_CHECK(page_table_row_index->scalar_type() == at::ScalarType::Int);
    page_table_row_index_ptr = page_table_row_index->data_ptr<int32_t>();
  }

  const int32_t* offsets_ptr = nullptr;
  if (topk_indices_offset.has_value()) {
    CHECK_CUDA(topk_indices_offset.value());
    CHECK_CONTIGUOUS(topk_indices_offset.value());
    TORCH_CHECK(topk_indices_offset->scalar_type() == at::ScalarType::Int);
    TORCH_CHECK(topk_indices_offset->size(0) == score.size(0));
    offsets_ptr = topk_indices_offset->data_ptr<int32_t>();
  }
  const int32_t* row_starts_ptr = nullptr;
  if (row_starts.has_value()) {
    CHECK_CUDA(row_starts.value());
    CHECK_CONTIGUOUS(row_starts.value());
    TORCH_CHECK(row_starts->scalar_type() == at::ScalarType::Int);
    TORCH_CHECK(row_starts->size(0) == score.size(0));
    row_starts_ptr = row_starts->data_ptr<int32_t>();
  }
  const int32_t* seq_lens_ptr = nullptr;
  if (seq_lens.has_value()) {
    CHECK_CUDA(seq_lens.value());
    CHECK_CONTIGUOUS(seq_lens.value());
    TORCH_CHECK(seq_lens->scalar_type() == at::ScalarType::Int);
    TORCH_CHECK(seq_lens->size(0) == score.size(0));
    seq_lens_ptr = seq_lens->data_ptr<int32_t>();
  }

  const bool sort_writeback = sort_writeback_enabled();
  const int64_t page_table_rows = page_table.has_value() ? page_table->size(0) : 0;
  const int64_t page_table_cols = page_table.has_value() ? page_table->size(1) : 0;

#define LAUNCH_FAST_KPOOL_TOPK(BLOCK_THREADS, SORT_WRITEBACK, POOL_SIZE, GROUP_TOPK) \
  launch_kpool_topk<BLOCK_THREADS, SORT_WRITEBACK, POOL_SIZE, GROUP_TOPK>(           \
      score,                                                                         \
      lengths,                                                                       \
      out,                                                                           \
      page_table_ptr,                                                                \
      page_table_stride,                                                             \
      page_table_rows,                                                               \
      page_table_cols,                                                               \
      page_table_row_index_ptr,                                                      \
      offsets_ptr,                                                                   \
      row_starts_ptr,                                                                \
      seq_lens_ptr)

  if (pool_size == 16 && group_topk == 128) {
    if (sort_writeback) {
      LAUNCH_FAST_KPOOL_TOPK(kKpoolTopkBlockThreads16, true, kKpoolTopkPoolSize16, kKpoolTopkGroupTopK128);
    } else {
      LAUNCH_FAST_KPOOL_TOPK(kKpoolTopkBlockThreads16, false, kKpoolTopkPoolSize16, kKpoolTopkGroupTopK128);
    }
  } else if (pool_size == 4 && group_topk == 512) {
    if (sort_writeback) {
      LAUNCH_FAST_KPOOL_TOPK(kKpoolTopkBlockThreads4, true, kKpoolTopkPoolSize4, kKpoolTopkGroupTopK512);
    } else {
      LAUNCH_FAST_KPOOL_TOPK(kKpoolTopkBlockThreads4, false, kKpoolTopkPoolSize4, kKpoolTopkGroupTopK512);
    }
  } else {
    TORCH_CHECK(false, "unsupported optimized kpool_topk path");
  }
#undef LAUNCH_FAST_KPOOL_TOPK

  auto err = cudaGetLastError();
  TORCH_CHECK(err == cudaSuccess, "kpool_topk failed: ", cudaGetErrorString(err));
}
