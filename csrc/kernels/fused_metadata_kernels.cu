// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
// SPDX-License-Identifier: MIT

#include <ATen/hip/HIPContext.h>
#include <ATen/hip/impl/HIPGuardImplMasqueradingAsCUDA.h>
#include <torch/all.h>

#include <hip/hip_runtime.h>

#include "fused_metadata.h"

#include <limits>
#include <optional>

// -----------------------------------------------------------------------------
// Fused metadata kernel for paged attention inference — host-dispatch deploy
// build: three implementation kernels of the same algorithm in one
// translation unit, selected on the host.  No runtime branches inside the
// kernels.
//
//   fused_metadata_kernel_a   tile 2048 (8 pages/thread, stride loop)
//   fused_metadata_kernel_b   tile 1024 (4 pages/thread, stride loop)
//   fused_metadata_kernel_c   tile  256 (tile == block, 1 page/thread)
//
// Routing rule (host-side integer math, calibrated from measured event
// timings; the workgroup count at the U-curve bottom is WG ≈ 256, i.e.
// waves ≈ 1024 with 256-thread blocks and 8 pages/thread):
//
//   WG(tile) = B * ceil(max_seq_pages / tile)     [waves = WG * 256 / 64]
//   Measured event ms at representative configs:
//     (128,4096)    : A(WG 256) 0.027 < B(512) 0.030 < C(1024) 0.039
//     (64,4096)     : B(WG 256) 0.018 < A(128) 0.019 < C(1024) 0.021
//     (8,4096,ps32) : C(WG 128) 0.007 < B(32) 0.008 ≈ A(16) 0.009
//
//   wg_a = B * ceil(P / 2048);  wg_b = B * ceil(P / 1024);
//   wg_a >= 256  -> A (tile 2048)
//   wg_b >= 256  -> B (tile 1024)
//   otherwise    -> C (tile 256)   [launch-floor configs; tile 256 has the
//                                   highest available concurrency]
//
//   use_swa / page_size do NOT participate in routing (tile geometry is
//   swa-independent; P is already a page count).  B = 0 returns on the host
//   before routing.  B > 64*kMaxScanGroups keeps the serial Phase-1 fallback,
//   so XL batch sizes stay functionally correct on every branch.
//
// Kernel structure:
//   • The three __global__ kernels are self-contained implementations: each
//     runs the shared Phase-1 prefix scan, then its own Phase-2 page gather —
//     A/B use a kTileA/kTileB-wide tile per blockIdx.y with the kBlockCols-
//     strided loop over [tile_base, min(tile_base + kTileA/kTileB, max_seq_pages));
//     C writes one column per thread (col = blockIdx.y*256 + threadIdx.x,
//     one tail guard).  The only tail guard is the global column boundary,
//     so every page in [0, max_seq_pages) is covered exactly once.
//   • Shared device helpers: fused_metadata_phase1_prefix_scan (identical for
//     all variants; the double-buffered LDS array is declared in each
//     __global__ kernel) and fused_metadata_gather_one_col (per-column body:
//     SHIFT 0/1 paths, int64 scaling, SWA mapping indexed with the unshifted
//     page_index).
//
// Host side: fused_metadata_kernel_general validates inputs/outputs, routes
// on the workgroup count (A/B/C), dispatches dtype (8 zero-copy combos) and
// use_swa/page_size, then launch_fused_metadata_variant computes the grid
// and launches the selected kernel.  The pybind signature in rocm_ops.hpp /
// kvcache_metadata_pybind.cu / python kvcache_metadata.py is unchanged.
//
// @tparam USE_SWA  Whether to build the SWA page table.
// @tparam SHIFT    0 when page_size=1 (dense gather), 1 otherwise
//                  (page c gathers req_to_token[row, c*page_size]).
// @tparam index_t    Integer type for seq_lens (int32_t or int64_t).
// @tparam pool_idx_t Integer type for req_pool_indices (int32_t or int64_t).
// @tparam mapping_t  Integer type for full_to_swa_mapping (int32_t or int64_t).
// -----------------------------------------------------------------------------

constexpr int kBlockCols = 256;
static_assert(kBlockCols >= 64 && kBlockCols % 64 == 0,
              "BLOCK_COLS must contain complete wavefronts");

// Phase-1 scan geometry (identical across the three tile variants).
constexpr int kPrefixLanes = 64;
constexpr int kMaxScanGroups = 16;

// Deploy variants (A/B/C) and their Phase-2 page tiles.  Each tile must be a
// multiple of kBlockCols.
constexpr int kTileA = 2048; // A：8 pages/thread 步长循环
constexpr int kTileB = 1024; // B：4 pages/thread 步长循环
constexpr int kTileC = 256;  // C：tile == block，单列直写
static_assert(kTileA % kBlockCols == 0 && kTileB % kBlockCols == 0 &&
                  kTileC % kBlockCols == 0,
              "deploy tiles must be multiples of BLOCK_COLS");

// Host-side variant selector threaded to the launch helper.
enum FusedMetadataVariant
{
  kVariantA = 0,
  kVariantB = 1,
  kVariantC = 2
};

// Routing threshold: workgroup count at the measured U-curve bottom
// (WG ≈ 256 ⇔ waves ≈ 1024 with 256-thread blocks).
constexpr int64_t kRouteWGThreshold = 256;

// -----------------------------------------------------------------------------
// Phase 1 — prefix-sum over seq_lens (block (0,0) only).
//   B <= 64                  : 6-round double-buffered LDS Hillis-Steele scan
//   64 < B <= 64*kMaxGroups  : row-group parallel scan + scalar group chain
//   B > 64*kMaxGroups        : thread-0 serial loop (controlled XL fallback,
//                              kept so any B stays correct)
// -----------------------------------------------------------------------------
template <typename index_t>
__device__ __forceinline__ void fused_metadata_phase1_prefix_scan(
    int64_t (*prefix_buf)[kPrefixLanes],
    const index_t *__restrict__ seq_lens,
    int32_t seq_lens_stride_0,
    int32_t *__restrict__ cache_seqlens_int32,
    int32_t cache_seqlens_int32_stride_0,
    int32_t *__restrict__ cu_seqlens_k,
    int32_t cu_seqlens_k_stride_0,
    int B,
    int seq_len_delta)
{
  if (blockIdx.x == 0 && blockIdx.y == 0)
  {
    const int tid = static_cast<int>(threadIdx.x);

    if (B <= kPrefixLanes)
    {
      // tid >= B lanes must not read seq_lens (B < 64); they scan as zero so
      // the left-to-right exclusive prefix semantics stay identical.  With
      // kBlockCols >= 64 every lane 0..63 exists in block (0,0).
      int64_t local_value = 0;
      if (tid < B)
      {
        const int64_t seq = static_cast<int64_t>(seq_lens[tid * seq_lens_stride_0]);
        local_value = seq + static_cast<int64_t>(seq_len_delta);
      }

      if (tid < kPrefixLanes)
        prefix_buf[0][tid] = local_value;

      // Must be reached by all kBlockCols threads of block (0,0).
      __syncthreads();

      // Hillis-Steele inclusive scan over the 64 lanes, 6 rounds.
      int src = 0;
      for (int offset = 1; offset < kPrefixLanes; offset <<= 1)
      {
        if (tid < kPrefixLanes)
        {
          const int64_t prior =
              (tid >= offset) ? prefix_buf[src][tid - offset] : int64_t{0};
          prefix_buf[1 - src][tid] = prefix_buf[src][tid] + prior;
        }

        // All tid>=64 threads of block (0,0) must reach this barrier too.
        __syncthreads();
        src = 1 - src;
      }

      if (B == 0)
      {
        // Empty batch: cu_seqlens_k's only element is defined as 0.  The host
        // fast path returns before launch; this stays as kernel-side defence.
        if (tid == 0)
          cu_seqlens_k[0] = 0;
      }
      else if (tid < B)
      {
        const int64_t inclusive = prefix_buf[src][tid];
        const int64_t exclusive = inclusive - local_value;
        cache_seqlens_int32[tid * cache_seqlens_int32_stride_0] =
            static_cast<int32_t>(local_value);
        cu_seqlens_k[tid * cu_seqlens_k_stride_0] = static_cast<int32_t>(exclusive);

        if (tid == B - 1)
          cu_seqlens_k[B * cu_seqlens_k_stride_0] = static_cast<int32_t>(inclusive);
      }
    }
    else if (B <= kPrefixLanes * kMaxScanGroups)
    {
      // 64 行/组并行扫描 + 组间标量链。
      // running_offset 每线程各自维护；所有线程每轮累加同一个 LDS 槽
      // （prefix_buf[src][group_rows-1]，组总和），故各线程值始终一致（uniform）。
      int64_t running_offset = 0;
      const int num_groups = (B + kPrefixLanes - 1) / kPrefixLanes;

      for (int g = 0; g < num_groups; ++g)
      {
        const int row_base = g * kPrefixLanes;
        const int group_rows = (B - row_base < kPrefixLanes)
                                   ? (B - row_base)
                                   : kPrefixLanes;

        // ① 装载：无效 lane（tid ≥ group_rows）以 0 参与扫描，不读 seq_lens。
        int64_t local_value = 0;
        if (tid < group_rows)
        {
          const int row = row_base + tid;
          const int64_t seq = static_cast<int64_t>(
              seq_lens[row * seq_lens_stride_0]);
          local_value = seq + static_cast<int64_t>(seq_len_delta);
        }

        if (tid < kPrefixLanes)
          prefix_buf[0][tid] = local_value;

        // 必须由 block (0,0) 全部 kBlockCols 个线程到达（在 tid 条件之外）。
        __syncthreads();

        // ② 6 轮 Hillis-Steele inclusive scan（与 B≤64 分支逐行同构）。
        int src = 0;
        for (int offset = 1; offset < kPrefixLanes; offset <<= 1)
        {
          if (tid < kPrefixLanes)
          {
            const int64_t prior = (tid >= offset)
                ? prefix_buf[src][tid - offset]
                : int64_t{0};
            prefix_buf[1 - src][tid] = prefix_buf[src][tid] + prior;
          }

          __syncthreads();
          src = 1 - src;
        }

        // ③ 写本组输出：cu = 全局偏移 + 组内 exclusive（保持 exclusive 语义）。
        if (tid < group_rows)
        {
          const int row = row_base + tid;
          const int64_t inclusive = prefix_buf[src][tid];
          const int64_t exclusive = inclusive - local_value;
          cache_seqlens_int32[row * cache_seqlens_int32_stride_0] =
              static_cast<int32_t>(local_value);
          cu_seqlens_k[row * cu_seqlens_k_stride_0] =
              static_cast<int32_t>(running_offset + exclusive);

          if (row == B - 1)
          {
            // 最后一个有效行写总和；此时 inclusive + running_offset 即全 B 总和。
            cu_seqlens_k[B * cu_seqlens_k_stride_0] =
                static_cast<int32_t>(running_offset + inclusive);
          }
        }

        // ④ 组间链：所有线程读同一槽（组总和），保持 uniform。
        running_offset += prefix_buf[src][group_rows - 1];

        // ⑤ 下一组将重写 prefix_buf[0]：本屏障保证本组所有读已完成；
        //    同时保证组间链更新对所有线程可见。必须由全块线程到达。
        __syncthreads();
      }
    }
    else if (tid == 0)
    {
      // B > 64*kMaxScanGroups 受控回退：thread-0 串行循环，保持左到右 int64 语义。
      int64_t acc = 0;
      for (int idx = 0; idx < B; ++idx)
      {
        int64_t seq = static_cast<int64_t>(seq_lens[idx * seq_lens_stride_0]);
        int64_t val = seq + static_cast<int64_t>(seq_len_delta);
        cache_seqlens_int32[idx * cache_seqlens_int32_stride_0] = static_cast<int32_t>(val);
        cu_seqlens_k[idx * cu_seqlens_k_stride_0] = static_cast<int32_t>(acc);
        acc += val;
      }
      cu_seqlens_k[B * cu_seqlens_k_stride_0] = static_cast<int32_t>(acc);
    }
  }
}

// -----------------------------------------------------------------------------
// Phase 2 per-column gather (shared by all three tile variants).
//   token_col = col * page_size_ is computed in int64 to avoid overflow; the
//   SWA mapping is indexed with the unshifted page_index and shifted only
//   when the swa_page_table value is written.
// -----------------------------------------------------------------------------
template <bool USE_SWA, int SHIFT, typename pool_idx_t, typename mapping_t>
__device__ __forceinline__ void fused_metadata_gather_one_col(
    int i,
    int col,
    const int32_t *__restrict__ req_to_token,
    int64_t req_to_token_stride_0,
    int64_t req_to_token_stride_1,
    const pool_idx_t *__restrict__ req_pool_indices,
    int32_t req_pool_indices_stride_0,
    int32_t *__restrict__ page_table,
    int64_t page_table_stride_0,
    int64_t page_table_stride_1,
    int32_t *__restrict__ swa_page_table,
    int64_t swa_page_table_stride_0,
    int64_t swa_page_table_stride_1,
    const mapping_t *__restrict__ full_to_swa_mapping,
    int64_t full_to_swa_mapping_stride_0,
    int page_size_,
    int shift_)
{
  const pool_idx_t row_idx = req_pool_indices[i * req_pool_indices_stride_0];
  const int64_t row_off = static_cast<int64_t>(row_idx) * req_to_token_stride_0;
  const int64_t pt_off = static_cast<int64_t>(i) * page_table_stride_0
                       + static_cast<int64_t>(col) * page_table_stride_1;

  int page_index;
  if constexpr (SHIFT == 0)
  {
    // page_size == 1: page col corresponds to token col.
    page_index = req_to_token[
        row_off + static_cast<int64_t>(col) * req_to_token_stride_1];
    page_table[pt_off] = page_index;
  }
  else
  {
    // page_size > 1: each page gathers its first token; int64 to avoid
    // col * page_size_ overflow.
    const int64_t token_col = static_cast<int64_t>(col) * page_size_;
    page_index = req_to_token[row_off + token_col * req_to_token_stride_1];
    page_table[pt_off] = page_index >> shift_;
  }

  if constexpr (USE_SWA)
  {
    const int64_t mapped = static_cast<int64_t>(
        full_to_swa_mapping[static_cast<int64_t>(page_index)
                            * full_to_swa_mapping_stride_0]);
    const int64_t swa_off = static_cast<int64_t>(i) * swa_page_table_stride_0
                          + static_cast<int64_t>(col) * swa_page_table_stride_1;
    if constexpr (SHIFT == 0)
      swa_page_table[swa_off] = static_cast<int32_t>(mapped);
    else
      swa_page_table[swa_off] = static_cast<int32_t>(mapped >> shift_);
  }
}

// -----------------------------------------------------------------------------
// Implementation kernel A — tile 2048 (8 pages/thread, kBlockCols-strided
// loop).  Phase 1 runs in block (0,0); Phase 2 covers [tile_base, tile_end).
// -----------------------------------------------------------------------------
template <bool USE_SWA, int SHIFT, typename index_t, typename pool_idx_t, typename mapping_t>
__global__ __launch_bounds__(kBlockCols, 2) void fused_metadata_kernel_a(
    const index_t *__restrict__ seq_lens,
    int32_t seq_lens_stride_0,
    const int32_t *__restrict__ req_to_token,
    int64_t req_to_token_stride_0,
    int64_t req_to_token_stride_1,
    bool req_to_token_contiguous, // kept for host-side compatibility (unused)
    const pool_idx_t *__restrict__ req_pool_indices,
    int32_t req_pool_indices_stride_0,
    int32_t *__restrict__ cache_seqlens_int32,
    int32_t cache_seqlens_int32_stride_0,
    int32_t *__restrict__ cu_seqlens_k,
    int32_t cu_seqlens_k_stride_0,
    int32_t *__restrict__ page_table,
    int64_t page_table_stride_0,
    int64_t page_table_stride_1,
    int32_t *__restrict__ swa_page_table,
    int64_t swa_page_table_stride_0,
    int64_t swa_page_table_stride_1,
    const mapping_t *__restrict__ full_to_swa_mapping,
    int64_t full_to_swa_mapping_stride_0,
    int B,
    int max_seq_pages,
    int page_size_,
    int seq_len_delta,
    int shift_)
{
  __shared__ int64_t prefix_buf[2][kPrefixLanes];

  fused_metadata_phase1_prefix_scan<index_t>(
      prefix_buf,
      seq_lens, seq_lens_stride_0,
      cache_seqlens_int32, cache_seqlens_int32_stride_0,
      cu_seqlens_k, cu_seqlens_k_stride_0,
      B, seq_len_delta);

  // Phase 2 — page-table gather.  The only tail guard is the global column
  // boundary, so every page in [0, max_seq_pages) is covered exactly once.
  if (max_seq_pages <= 0)
    return;

  (void)req_to_token_contiguous;

  const int i = static_cast<int>(blockIdx.x);
  const int tile_base = static_cast<int>(blockIdx.y) * kTileA;
  int tile_end = tile_base + kTileA;
  if (tile_end > max_seq_pages)
    tile_end = max_seq_pages;

  for (int col = tile_base + static_cast<int>(threadIdx.x);
       col < tile_end;
       col += kBlockCols)
  {
    fused_metadata_gather_one_col<USE_SWA, SHIFT, pool_idx_t, mapping_t>(
        i, col,
        req_to_token, req_to_token_stride_0, req_to_token_stride_1,
        req_pool_indices, req_pool_indices_stride_0,
        page_table, page_table_stride_0, page_table_stride_1,
        swa_page_table, swa_page_table_stride_0, swa_page_table_stride_1,
        full_to_swa_mapping, full_to_swa_mapping_stride_0,
        page_size_, shift_);
  }
}

// -----------------------------------------------------------------------------
// Implementation kernel B — tile 1024 (4 pages/thread, kBlockCols-strided
// loop).  Phase 1 runs in block (0,0); Phase 2 covers [tile_base, tile_end).
// -----------------------------------------------------------------------------
template <bool USE_SWA, int SHIFT, typename index_t, typename pool_idx_t, typename mapping_t>
__global__ __launch_bounds__(kBlockCols, 2) void fused_metadata_kernel_b(
    const index_t *__restrict__ seq_lens,
    int32_t seq_lens_stride_0,
    const int32_t *__restrict__ req_to_token,
    int64_t req_to_token_stride_0,
    int64_t req_to_token_stride_1,
    bool req_to_token_contiguous, // kept for host-side compatibility (unused)
    const pool_idx_t *__restrict__ req_pool_indices,
    int32_t req_pool_indices_stride_0,
    int32_t *__restrict__ cache_seqlens_int32,
    int32_t cache_seqlens_int32_stride_0,
    int32_t *__restrict__ cu_seqlens_k,
    int32_t cu_seqlens_k_stride_0,
    int32_t *__restrict__ page_table,
    int64_t page_table_stride_0,
    int64_t page_table_stride_1,
    int32_t *__restrict__ swa_page_table,
    int64_t swa_page_table_stride_0,
    int64_t swa_page_table_stride_1,
    const mapping_t *__restrict__ full_to_swa_mapping,
    int64_t full_to_swa_mapping_stride_0,
    int B,
    int max_seq_pages,
    int page_size_,
    int seq_len_delta,
    int shift_)
{
  __shared__ int64_t prefix_buf[2][kPrefixLanes];

  fused_metadata_phase1_prefix_scan<index_t>(
      prefix_buf,
      seq_lens, seq_lens_stride_0,
      cache_seqlens_int32, cache_seqlens_int32_stride_0,
      cu_seqlens_k, cu_seqlens_k_stride_0,
      B, seq_len_delta);

  // Phase 2 — page-table gather.  The only tail guard is the global column
  // boundary, so every page in [0, max_seq_pages) is covered exactly once.
  if (max_seq_pages <= 0)
    return;

  (void)req_to_token_contiguous;

  const int i = static_cast<int>(blockIdx.x);
  const int tile_base = static_cast<int>(blockIdx.y) * kTileB;
  int tile_end = tile_base + kTileB;
  if (tile_end > max_seq_pages)
    tile_end = max_seq_pages;

  for (int col = tile_base + static_cast<int>(threadIdx.x);
       col < tile_end;
       col += kBlockCols)
  {
    fused_metadata_gather_one_col<USE_SWA, SHIFT, pool_idx_t, mapping_t>(
        i, col,
        req_to_token, req_to_token_stride_0, req_to_token_stride_1,
        req_pool_indices, req_pool_indices_stride_0,
        page_table, page_table_stride_0, page_table_stride_1,
        swa_page_table, swa_page_table_stride_0, swa_page_table_stride_1,
        full_to_swa_mapping, full_to_swa_mapping_stride_0,
        page_size_, shift_);
  }
}

// -----------------------------------------------------------------------------
// Implementation kernel C — tile 256 (tile == block, one page column per
// thread).  Phase 1 runs in block (0,0); Phase 2 is the single-col form.
// -----------------------------------------------------------------------------
template <bool USE_SWA, int SHIFT, typename index_t, typename pool_idx_t, typename mapping_t>
__global__ __launch_bounds__(kBlockCols, 2) void fused_metadata_kernel_c(
    const index_t *__restrict__ seq_lens,
    int32_t seq_lens_stride_0,
    const int32_t *__restrict__ req_to_token,
    int64_t req_to_token_stride_0,
    int64_t req_to_token_stride_1,
    bool req_to_token_contiguous, // kept for host-side compatibility (unused)
    const pool_idx_t *__restrict__ req_pool_indices,
    int32_t req_pool_indices_stride_0,
    int32_t *__restrict__ cache_seqlens_int32,
    int32_t cache_seqlens_int32_stride_0,
    int32_t *__restrict__ cu_seqlens_k,
    int32_t cu_seqlens_k_stride_0,
    int32_t *__restrict__ page_table,
    int64_t page_table_stride_0,
    int64_t page_table_stride_1,
    int32_t *__restrict__ swa_page_table,
    int64_t swa_page_table_stride_0,
    int64_t swa_page_table_stride_1,
    const mapping_t *__restrict__ full_to_swa_mapping,
    int64_t full_to_swa_mapping_stride_0,
    int B,
    int max_seq_pages,
    int page_size_,
    int seq_len_delta,
    int shift_)
{
  __shared__ int64_t prefix_buf[2][kPrefixLanes];

  fused_metadata_phase1_prefix_scan<index_t>(
      prefix_buf,
      seq_lens, seq_lens_stride_0,
      cache_seqlens_int32, cache_seqlens_int32_stride_0,
      cu_seqlens_k, cu_seqlens_k_stride_0,
      B, seq_len_delta);

  // Phase 2 — page-table gather: one thread per global page column, single-
  // col form with one tail guard.
  if (max_seq_pages <= 0)
    return;

  (void)req_to_token_contiguous;

  const int i = static_cast<int>(blockIdx.x);
  const int col = static_cast<int>(blockIdx.y) * kBlockCols
                + static_cast<int>(threadIdx.x);
  if (col >= max_seq_pages)
    return;

  fused_metadata_gather_one_col<USE_SWA, SHIFT, pool_idx_t, mapping_t>(
      i, col,
      req_to_token, req_to_token_stride_0, req_to_token_stride_1,
      req_pool_indices, req_pool_indices_stride_0,
      page_table, page_table_stride_0, page_table_stride_1,
      swa_page_table, swa_page_table_stride_0, swa_page_table_stride_1,
      full_to_swa_mapping, full_to_swa_mapping_stride_0,
      page_size_, shift_);
}

// -----------------------------------------------------------------------------
// Host-side launch helper — grid/block per variant tile, then a plain
// three-way dispatch to the implementation kernel.
// -----------------------------------------------------------------------------
template <bool USE_SWA, int SHIFT, typename index_t, typename pool_idx_t, typename mapping_t>
void launch_fused_metadata_variant(
    FusedMetadataVariant variant,
    const index_t *ptr_seq_lens, int32_t sl_s0,
    const int32_t *ptr_req2tok, int64_t r2t_s0, int64_t r2t_s1, bool r2t_contig,
    const pool_idx_t *ptr_pool_idx, int32_t pi_s0,
    int32_t *ptr_cache_seql, int32_t cs_s0,
    int32_t *ptr_cu_seql, int32_t cu_s0,
    int32_t *ptr_page_tbl, int64_t pt_s0, int64_t pt_s1,
    int32_t *ptr_swa_pt, int64_t spt_s0, int64_t spt_s1,
    const mapping_t *ptr_swa_map, int64_t fts_s0,
    int B_i, int P_i, int ps_i, int delta_i, int shift,
    const hipStream_t &stream)
{
  const int tile = (variant == kVariantA) ? kTileA
                 : (variant == kVariantB) ? kTileB
                                          : kTileC;

  // 2D grid — x = batch row, y = page tile.  grid_y >= 1 keeps (0,0)
  // launchable when P == 0 (Phase 1 still runs); B == 0 returns on the host
  // before launch.  "1 + (P-1)/tile" avoids P + tile - 1 overflow.
  const int grid_y = (P_i > 0) ? 1 + (P_i - 1) / tile : 1;
  dim3 grid(static_cast<unsigned>(B_i), static_cast<unsigned>(grid_y), 1u);
  dim3 block(static_cast<unsigned>(kBlockCols), 1u, 1u);

  if (variant == kVariantA)
  {
    fused_metadata_kernel_a<USE_SWA, SHIFT, index_t, pool_idx_t, mapping_t>
        <<<grid, block, 0, stream>>>(
            ptr_seq_lens, sl_s0,
            ptr_req2tok, r2t_s0, r2t_s1, r2t_contig,
            ptr_pool_idx, pi_s0,
            ptr_cache_seql, cs_s0,
            ptr_cu_seql, cu_s0,
            ptr_page_tbl, pt_s0, pt_s1,
            ptr_swa_pt, spt_s0, spt_s1,
            ptr_swa_map, fts_s0,
            B_i, P_i, ps_i, delta_i, shift);
  }
  else if (variant == kVariantB)
  {
    fused_metadata_kernel_b<USE_SWA, SHIFT, index_t, pool_idx_t, mapping_t>
        <<<grid, block, 0, stream>>>(
            ptr_seq_lens, sl_s0,
            ptr_req2tok, r2t_s0, r2t_s1, r2t_contig,
            ptr_pool_idx, pi_s0,
            ptr_cache_seql, cs_s0,
            ptr_cu_seql, cu_s0,
            ptr_page_tbl, pt_s0, pt_s1,
            ptr_swa_pt, spt_s0, spt_s1,
            ptr_swa_map, fts_s0,
            B_i, P_i, ps_i, delta_i, shift);
  }
  else
  {
    fused_metadata_kernel_c<USE_SWA, SHIFT, index_t, pool_idx_t, mapping_t>
        <<<grid, block, 0, stream>>>(
            ptr_seq_lens, sl_s0,
            ptr_req2tok, r2t_s0, r2t_s1, r2t_contig,
            ptr_pool_idx, pi_s0,
            ptr_cache_seql, cs_s0,
            ptr_cu_seql, cu_s0,
            ptr_page_tbl, pt_s0, pt_s1,
            ptr_swa_pt, spt_s0, spt_s1,
            ptr_swa_map, fts_s0,
            B_i, P_i, ps_i, delta_i, shift);
  }
}

// -----------------------------------------------------------------------------
// Host-side dispatch helper (templated on the input dtypes) — pointer/stride
// extraction identical for every variant, then use_swa/page_size dispatch.
// -----------------------------------------------------------------------------
template <typename index_t, typename pool_idx_t, typename mapping_t>
void fused_metadata_dispatch_impl(
    FusedMetadataVariant variant,
    torch::Tensor seq_lens,
    torch::Tensor req_to_token,
    torch::Tensor req_pool_indices,
    torch::Tensor &cache_seqlens_int32,
    torch::Tensor &cu_seqlens_k,
    torch::Tensor &page_table,
    const std::optional<torch::Tensor> &swa_page_table,
    const std::optional<torch::Tensor> &full_to_swa_mapping,
    int64_t B,
    int64_t max_seq_pages,
    int64_t page_size,
    int64_t seq_len_delta,
    bool use_swa,
    int shift,
    const hipStream_t &stream)
{
  const index_t *ptr_seq_lens = seq_lens.data_ptr<index_t>();
  const int32_t *ptr_req2tok = req_to_token.data_ptr<int32_t>();
  const pool_idx_t *ptr_pool_idx = req_pool_indices.data_ptr<pool_idx_t>();
  int32_t *ptr_cache_seql = cache_seqlens_int32.data_ptr<int32_t>();
  int32_t *ptr_cu_seql = cu_seqlens_k.data_ptr<int32_t>();
  int32_t *ptr_page_tbl = page_table.data_ptr<int32_t>();

  int32_t *ptr_swa_pt =
      swa_page_table.has_value() ? swa_page_table->data_ptr<int32_t>() : nullptr;
  const mapping_t *ptr_swa_map = full_to_swa_mapping.has_value()
                                     ? full_to_swa_mapping->data_ptr<mapping_t>()
                                     : nullptr;

  const int64_t spt_s0 = swa_page_table.has_value() ? swa_page_table->stride(0) : 0;
  const int64_t spt_s1 = swa_page_table.has_value() ? swa_page_table->stride(1) : 0;
  const int64_t fts_s0 = full_to_swa_mapping.has_value() ? full_to_swa_mapping->stride(0) : 0;

  // Kept for signature compatibility; the kernel no longer reads it.
  const bool r2t_contig = req_to_token.is_contiguous() && req_to_token.stride(1) == 1;

  const int B_i = static_cast<int>(B);
  const int P_i = static_cast<int>(max_seq_pages);
  const int ps_i = static_cast<int>(page_size);
  const int delta_i = static_cast<int>(seq_len_delta);

  // Dispatch to the right kernel template: SHIFT=0 (page_size=1) or SHIFT=1.
  if (use_swa)
  {
    if (page_size <= 1)
    {
      launch_fused_metadata_variant<true, 0, index_t, pool_idx_t, mapping_t>(
          variant, ptr_seq_lens, static_cast<int32_t>(seq_lens.stride(0)),
          ptr_req2tok, static_cast<int64_t>(req_to_token.stride(0)),
          static_cast<int64_t>(req_to_token.stride(1)), r2t_contig,
          ptr_pool_idx, static_cast<int32_t>(req_pool_indices.stride(0)),
          ptr_cache_seql, static_cast<int32_t>(cache_seqlens_int32.stride(0)),
          ptr_cu_seql, static_cast<int32_t>(cu_seqlens_k.stride(0)),
          ptr_page_tbl, static_cast<int64_t>(page_table.stride(0)),
          static_cast<int64_t>(page_table.stride(1)),
          ptr_swa_pt, spt_s0, spt_s1,
          ptr_swa_map, fts_s0,
          B_i, P_i, ps_i, delta_i, shift, stream);
    }
    else
    {
      launch_fused_metadata_variant<true, 1, index_t, pool_idx_t, mapping_t>(
          variant, ptr_seq_lens, static_cast<int32_t>(seq_lens.stride(0)),
          ptr_req2tok, static_cast<int64_t>(req_to_token.stride(0)),
          static_cast<int64_t>(req_to_token.stride(1)), r2t_contig,
          ptr_pool_idx, static_cast<int32_t>(req_pool_indices.stride(0)),
          ptr_cache_seql, static_cast<int32_t>(cache_seqlens_int32.stride(0)),
          ptr_cu_seql, static_cast<int32_t>(cu_seqlens_k.stride(0)),
          ptr_page_tbl, static_cast<int64_t>(page_table.stride(0)),
          static_cast<int64_t>(page_table.stride(1)),
          ptr_swa_pt, spt_s0, spt_s1,
          ptr_swa_map, fts_s0,
          B_i, P_i, ps_i, delta_i, shift, stream);
    }
  }
  else
  {
    if (page_size <= 1)
    {
      launch_fused_metadata_variant<false, 0, index_t, pool_idx_t, mapping_t>(
          variant, ptr_seq_lens, static_cast<int32_t>(seq_lens.stride(0)),
          ptr_req2tok, static_cast<int64_t>(req_to_token.stride(0)),
          static_cast<int64_t>(req_to_token.stride(1)), r2t_contig,
          ptr_pool_idx, static_cast<int32_t>(req_pool_indices.stride(0)),
          ptr_cache_seql, static_cast<int32_t>(cache_seqlens_int32.stride(0)),
          ptr_cu_seql, static_cast<int32_t>(cu_seqlens_k.stride(0)),
          ptr_page_tbl, static_cast<int64_t>(page_table.stride(0)),
          static_cast<int64_t>(page_table.stride(1)),
          static_cast<int32_t *>(nullptr), static_cast<int64_t>(0), static_cast<int64_t>(0),
          static_cast<const mapping_t *>(nullptr), static_cast<int64_t>(0),
          B_i, P_i, ps_i, delta_i, shift, stream);
    }
    else
    {
      launch_fused_metadata_variant<false, 1, index_t, pool_idx_t, mapping_t>(
          variant, ptr_seq_lens, static_cast<int32_t>(seq_lens.stride(0)),
          ptr_req2tok, static_cast<int64_t>(req_to_token.stride(0)),
          static_cast<int64_t>(req_to_token.stride(1)), r2t_contig,
          ptr_pool_idx, static_cast<int32_t>(req_pool_indices.stride(0)),
          ptr_cache_seql, static_cast<int32_t>(cache_seqlens_int32.stride(0)),
          ptr_cu_seql, static_cast<int32_t>(cu_seqlens_k.stride(0)),
          ptr_page_tbl, static_cast<int64_t>(page_table.stride(0)),
          static_cast<int64_t>(page_table.stride(1)),
          static_cast<int32_t *>(nullptr), static_cast<int64_t>(0), static_cast<int64_t>(0),
          static_cast<const mapping_t *>(nullptr), static_cast<int64_t>(0),
          B_i, P_i, ps_i, delta_i, shift, stream);
    }
  }
}

// -----------------------------------------------------------------------------
// Host-side launcher (validates inputs/outputs, applies the workgroup-count
// routing rule, then dispatches on dtype).  Exported through
// KVCACHE_METADATA_PYBIND — signature unchanged.
// -----------------------------------------------------------------------------
void fused_metadata_kernel_general(
    torch::Tensor seq_lens,
    torch::Tensor req_to_token,
    torch::Tensor req_pool_indices,
    torch::Tensor &cache_seqlens_int32,
    torch::Tensor &cu_seqlens_k,
    torch::Tensor &page_table,
    const std::optional<torch::Tensor> &swa_page_table,
    const std::optional<torch::Tensor> &full_to_swa_mapping,
    int64_t B,
    int64_t max_seq_pages,
    int64_t page_size,
    int64_t seq_len_delta,
    bool use_swa)
{
  const at::hip::OptionalHIPGuardMasqueradingAsCUDA device_guard(at::device_of(seq_lens));
  const hipStream_t stream = at::hip::getCurrentHIPStream();

  TORCH_CHECK(seq_lens.is_cuda(), "seq_lens must be a CUDA tensor");
  TORCH_CHECK(req_to_token.is_cuda(), "req_to_token must be a CUDA tensor");
  TORCH_CHECK(req_pool_indices.is_cuda(), "req_pool_indices must be a CUDA tensor");
  TORCH_CHECK(cache_seqlens_int32.is_cuda(), "cache_seqlens_int32 must be a CUDA tensor");
  TORCH_CHECK(cu_seqlens_k.is_cuda(), "cu_seqlens_k must be a CUDA tensor");
  TORCH_CHECK(page_table.is_cuda(), "page_table must be a CUDA tensor");
  if (swa_page_table.has_value())
  {
    TORCH_CHECK(swa_page_table->is_cuda(), "swa_page_table must be a CUDA tensor");
  }
  if (full_to_swa_mapping.has_value())
  {
    TORCH_CHECK(full_to_swa_mapping->is_cuda(), "full_to_swa_mapping must be a CUDA tensor");
  }

  // ---- boundary checks ----------------------------------------------------
  TORCH_CHECK(B >= 0, "B must be non-negative");
  TORCH_CHECK(max_seq_pages >= 0, "max_seq_pages must be non-negative");
  TORCH_CHECK(B <= std::numeric_limits<int>::max(), "B is too large");
  TORCH_CHECK(max_seq_pages <= std::numeric_limits<int>::max(),
              "max_seq_pages is too large");

  // ---- page_size validation -----------------------------------------------
  TORCH_CHECK(
      page_size >= 1 && (page_size & (page_size - 1)) == 0,
      "page_size must be a positive power of two, but got ", page_size);

  // ---- input dtype checks (no .to() conversion anywhere in dispatch) --------
  TORCH_CHECK(
      seq_lens.dtype() == torch::kInt32 || seq_lens.dtype() == torch::kInt64,
      "seq_lens must have dtype int32 or int64, but got ",
      c10::toString(seq_lens.scalar_type()));
  TORCH_CHECK(
      req_to_token.dtype() == torch::kInt32,
      "req_to_token must have dtype int32, but got ",
      c10::toString(req_to_token.scalar_type()));
  TORCH_CHECK(
      req_pool_indices.dtype() == torch::kInt32 || req_pool_indices.dtype() == torch::kInt64,
      "req_pool_indices must have dtype int32 or int64, but got ",
      c10::toString(req_pool_indices.scalar_type()));
  if (full_to_swa_mapping.has_value())
  {
    TORCH_CHECK(
        full_to_swa_mapping->dtype() == torch::kInt32 || full_to_swa_mapping->dtype() == torch::kInt64,
        "full_to_swa_mapping must have dtype int32 or int64, but got ",
        c10::toString(full_to_swa_mapping->scalar_type()));
  }

  // ---- input shape checks ---------------------------------------------------
  TORCH_CHECK(seq_lens.dim() == 1 && seq_lens.size(0) == B,
              "seq_lens must have shape [B], got ", seq_lens.sizes());
  TORCH_CHECK(req_pool_indices.dim() == 1 && req_pool_indices.size(0) == B,
              "req_pool_indices must have shape [B], got ", req_pool_indices.sizes());
  TORCH_CHECK(req_to_token.dim() == 2,
              "req_to_token must be 2-D [num_reqs, max_tokens], got ", req_to_token.sizes());

  // ---- use_swa contract -----------------------------------------------------
  if (use_swa)
  {
    TORCH_CHECK(swa_page_table.has_value(), "use_swa requires swa_page_table");
    TORCH_CHECK(full_to_swa_mapping.has_value(), "use_swa requires full_to_swa_mapping");
  }

  // ---- output dtype / contiguity / shape checks ------------------------------
  TORCH_CHECK(cache_seqlens_int32.dtype() == torch::kInt32,
              "cache_seqlens_int32 must have dtype int32");
  TORCH_CHECK(cu_seqlens_k.dtype() == torch::kInt32,
              "cu_seqlens_k must have dtype int32");
  TORCH_CHECK(page_table.dtype() == torch::kInt32,
              "page_table must have dtype int32");
  if (swa_page_table.has_value())
  {
    TORCH_CHECK(swa_page_table->dtype() == torch::kInt32,
                "swa_page_table must have dtype int32");
  }

  TORCH_CHECK(cache_seqlens_int32.is_contiguous(), "cache_seqlens_int32 must be contiguous");
  TORCH_CHECK(cu_seqlens_k.is_contiguous(), "cu_seqlens_k must be contiguous");
  TORCH_CHECK(page_table.is_contiguous(), "page_table must be contiguous");
  if (swa_page_table.has_value())
  {
    TORCH_CHECK(swa_page_table->is_contiguous(), "swa_page_table must be contiguous");
  }

  TORCH_CHECK(cache_seqlens_int32.size(0) == B,
              "cache_seqlens_int32 must have shape [B], got ", cache_seqlens_int32.sizes());
  TORCH_CHECK(cu_seqlens_k.size(0) == B + 1,
              "cu_seqlens_k must have shape [B + 1], got ", cu_seqlens_k.sizes());
  TORCH_CHECK(
      page_table.dim() == 2 && page_table.size(0) == B && page_table.size(1) == max_seq_pages,
      "page_table must have shape [B, max_seq_pages], got ", page_table.sizes());
  if (swa_page_table.has_value())
  {
    TORCH_CHECK(
        swa_page_table->dim() == 2 && swa_page_table->size(0) == B &&
            swa_page_table->size(1) == max_seq_pages,
        "swa_page_table must have shape [B, max_seq_pages], got ", swa_page_table->sizes());
  }

  // ---- empty-batch fast path -------------------------------------------------
  // Output shape is cache=[0], cu=[1], page_table=[0, P]; the sole cu element
  // must be 0.  Do not emit a grid.x=0 kernel launch.
  if (B == 0)
  {
    cu_seqlens_k.zero_();
    return;
  }

  // ---- shift = log2(page_size)  (page_size validated as a power of two) -----
  int shift = 0;
  if (page_size > 1)
  {
    int64_t tmp = page_size;
    while (tmp > 1)
    {
      tmp >>= 1;
      ++shift;
    }
  }

  // ---- Variant routing (A = tile 2048, B = tile 1024, C = tile 256) ----------
  // Pick the largest tile whose workgroup count still reaches the measured
  // U-curve bottom (WG ≈ 256 ⇔ waves ≈ 1024):
  //   wg_a >= 256 -> A (tile 2048)
  //   wg_b >= 256 -> B (tile 1024)
  //   otherwise   -> C (tile 256) — launch-floor configs, tile 256 keeps the
  //                  highest available concurrency and never loses there.
  // Integer-only int64 host math (B, P <= int::max, so wg fits comfortably);
  // use_swa / page_size deliberately do not participate.
  const int64_t wg_a = B * ((max_seq_pages + kTileA - 1) / kTileA);
  const int64_t wg_b = B * ((max_seq_pages + kTileB - 1) / kTileB);
  const FusedMetadataVariant variant = (wg_a >= kRouteWGThreshold) ? kVariantA
                                     : (wg_b >= kRouteWGThreshold) ? kVariantB
                                                                   : kVariantC;

  // ---- Dtype dispatch (8 zero-copy combinations, no .to()) --------------------
  const auto seq_dt = seq_lens.scalar_type();
  const auto pool_dt = req_pool_indices.scalar_type();
  const bool mapping_is_int64 =
      full_to_swa_mapping.has_value() && full_to_swa_mapping->scalar_type() == torch::kInt64;

  if (seq_dt == torch::kInt64 && pool_dt == torch::kInt64)
  {
    if (mapping_is_int64)
    {
      fused_metadata_dispatch_impl<int64_t, int64_t, int64_t>(
          variant, seq_lens, req_to_token, req_pool_indices, cache_seqlens_int32,
          cu_seqlens_k, page_table, swa_page_table, full_to_swa_mapping,
          B, max_seq_pages, page_size, seq_len_delta, use_swa, shift, stream);
    }
    else
    {
      fused_metadata_dispatch_impl<int64_t, int64_t, int32_t>(
          variant, seq_lens, req_to_token, req_pool_indices, cache_seqlens_int32,
          cu_seqlens_k, page_table, swa_page_table, full_to_swa_mapping,
          B, max_seq_pages, page_size, seq_len_delta, use_swa, shift, stream);
    }
  }
  else if (seq_dt == torch::kInt32 && pool_dt == torch::kInt32)
  {
    if (mapping_is_int64)
    {
      fused_metadata_dispatch_impl<int32_t, int32_t, int64_t>(
          variant, seq_lens, req_to_token, req_pool_indices, cache_seqlens_int32,
          cu_seqlens_k, page_table, swa_page_table, full_to_swa_mapping,
          B, max_seq_pages, page_size, seq_len_delta, use_swa, shift, stream);
    }
    else
    {
      fused_metadata_dispatch_impl<int32_t, int32_t, int32_t>(
          variant, seq_lens, req_to_token, req_pool_indices, cache_seqlens_int32,
          cu_seqlens_k, page_table, swa_page_table, full_to_swa_mapping,
          B, max_seq_pages, page_size, seq_len_delta, use_swa, shift, stream);
    }
  }
  else if (seq_dt == torch::kInt32 && pool_dt == torch::kInt64)
  {
    if (mapping_is_int64)
    {
      fused_metadata_dispatch_impl<int32_t, int64_t, int64_t>(
          variant, seq_lens, req_to_token, req_pool_indices, cache_seqlens_int32,
          cu_seqlens_k, page_table, swa_page_table, full_to_swa_mapping,
          B, max_seq_pages, page_size, seq_len_delta, use_swa, shift, stream);
    }
    else
    {
      fused_metadata_dispatch_impl<int32_t, int64_t, int32_t>(
          variant, seq_lens, req_to_token, req_pool_indices, cache_seqlens_int32,
          cu_seqlens_k, page_table, swa_page_table, full_to_swa_mapping,
          B, max_seq_pages, page_size, seq_len_delta, use_swa, shift, stream);
    }
  }
  else
  {
    // seq_lens int64, req_pool_indices int32
    if (mapping_is_int64)
    {
      fused_metadata_dispatch_impl<int64_t, int32_t, int64_t>(
          variant, seq_lens, req_to_token, req_pool_indices, cache_seqlens_int32,
          cu_seqlens_k, page_table, swa_page_table, full_to_swa_mapping,
          B, max_seq_pages, page_size, seq_len_delta, use_swa, shift, stream);
    }
    else
    {
      fused_metadata_dispatch_impl<int64_t, int32_t, int32_t>(
          variant, seq_lens, req_to_token, req_pool_indices, cache_seqlens_int32,
          cu_seqlens_k, page_table, swa_page_table, full_to_swa_mapping,
          B, max_seq_pages, page_size, seq_len_delta, use_swa, shift, stream);
    }
  }
}
