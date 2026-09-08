// SPDX-License-Identifier: MIT
#pragma once

#include "fla.h"

namespace FLA_NAMESPACE {

////////////////////////////////////////////////////////////////////////////////////////////////////
// BlockInfo
//
// Per-(batch, head) helper that resolves the begin-of-sequence and
// begin-of-chunk offsets, and exposes pointer-arithmetic helpers used by the
// kernel. Templated on Varlen so the compiler can DCE the unused branches.
// IndexT is the element type of cu_seqlens: int32 or int64.
// chunk_indices is host-only (NT) and is not read here.
// chunk_offsets is always int64 (SGLang cumsum promotion). Values are narrowed
// to int after load (same as Triton's .to(tl.int32)).
////////////////////////////////////////////////////////////////////////////////////////////////////
template <bool Varlen, typename IndexT = int32_t>
struct BlockInfo
{
    template <typename Params>
    __device__ BlockInfo(const Params &params, const int bidb)
        : bos_(Varlen && params.cu_seqlens != nullptr
                   ? int(reinterpret_cast<const IndexT *>(params.cu_seqlens)[bidb])
                   : bidb * params.T)
        , boh_(Varlen && params.chunk_offsets != nullptr
                   ? int(reinterpret_cast<const int64_t *>(params.chunk_offsets)[bidb])
                   : bidb * params.NT)
        , actual_seqlen_(Varlen && params.cu_seqlens != nullptr
                             ? int(reinterpret_cast<const IndexT *>(params.cu_seqlens)[bidb + 1] -
                                   reinterpret_cast<const IndexT *>(params.cu_seqlens)[bidb])
                             : params.T)
        , n_chunks_((actual_seqlen_ + params.BT - 1) / params.BT)
        , state_idx_(params.use_initial_state_indices
                         ? params.initial_state_indices[bidb]
                         : bidb)
        , has_state_(static_cast<unsigned int>(state_idx_) <
                     static_cast<unsigned int>(params.state_rows))
    {
    }

    // --- accessors ---
    __device__ __forceinline__ int bos()           const { return bos_; }
    __device__ __forceinline__ int boh()           const { return boh_; }
    __device__ __forceinline__ int actual_seqlen() const { return actual_seqlen_; }
    __device__ __forceinline__ int n_chunks()      const { return n_chunks_; }
    __device__ __forceinline__ int state_idx()     const { return state_idx_; }
    __device__ __forceinline__ bool has_state()    const { return has_state_; }

    /// last valid time index inside chunk @p chunk_idx
    __device__ __forceinline__ int last_idx(const int chunk_idx, const int BT) const
    {
        return min((chunk_idx + 1) * BT, actual_seqlen_) - 1;
    }

    // --- offset helpers  (all strides are in *elements*, not bytes) ---

    /// h  — chunked hidden state.   base = boh * H*K*V + head * head_stride
    template <typename index_t>
    __device__ __forceinline__ index_t h_offset(const int head_id,
                                                const index_t chunk_stride,
                                                const index_t head_stride) const
    {
        return index_t(boh_) * chunk_stride + index_t(head_id) * head_stride;
    }

    /// v (u) / v_new — value / residual.  base = bos * H*V + head * head_stride
    template <typename index_t>
    __device__ __forceinline__ index_t v_offset(const int head_id,
                                                const index_t row_stride,
                                                const index_t head_stride) const
    {
        return index_t(bos_) * row_stride + index_t(head_id) * head_stride;
    }

    /// k — key, with GQA group broadcasting.
    ///     base = bos * Hg*K + (head / h_h_k_ratio) * head_stride
    template <typename index_t>
    __device__ __forceinline__ index_t k_offset(const int head_id,
                                                const index_t row_stride,
                                                const index_t head_stride,
                                                const int h_h_k_ratio) const
    {
        return index_t(bos_) * row_stride + index_t(head_id / h_h_k_ratio) * head_stride;
    }

    /// w — weight/gate matrix.  base = bos * H*K + head * head_stride
    template <typename index_t>
    __device__ __forceinline__ index_t w_offset(const int head_id,
                                                const index_t row_stride,
                                                const index_t head_stride) const
    {
        return index_t(bos_) * row_stride + index_t(head_id) * head_stride;
    }

    /// g — scalar gate (3D: T×H).  base = bos * g_row_stride + head_id
    template <typename index_t>
    __device__ __forceinline__ index_t g_offset(const int head_id,
                                                const index_t row_stride) const
    {
        return index_t(bos_) * row_stride + index_t(head_id);
    }

    /// gk — per-channel gate (4D: T×H×K).  base = bos * H*K + head * head_stride
    template <typename index_t>
    __device__ __forceinline__ index_t gk_offset(const int head_id,
                                                 const index_t row_stride,
                                                 const index_t head_stride) const
    {
        return index_t(bos_) * row_stride + index_t(head_id) * head_stride;
    }

    /// h0 / ht — initial / final persistent state.
    ///     base = state_idx * batch_stride + head * head_stride
    template <typename index_t>
    __device__ __forceinline__ index_t state_offset(const int head_id,
                                                    const index_t batch_stride,
                                                    const index_t head_stride) const
    {
        return index_t(state_idx_) * batch_stride + index_t(head_id) * head_stride;
    }

private:
    const int bos_;            // beginning of sequence  (cu_seqlens[bidb] or bidb*T)
    const int boh_;            // beginning of chunk     (chunk_offsets[bidb] or bidb*NT)
    const int actual_seqlen_;  // length of this sequence
    const int n_chunks_;       // number of chunks in this sequence
    const int state_idx_;      // index into initial_state / final_state
    const bool has_state_;     // valid pool slot; false for -1/out-of-range
};

}  // namespace FLA_NAMESPACE
