// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
//
// CK GDN native adapter -- shared workspace layout.
//
// The CK GDN example (3rdparty/composable_kernel/example_hcu/ck_tile/21_gdn)
// keeps every intermediate buffer on the caller side (see gdn_prefill.cpp).
// The aiter native entry points reproduce that contract with a single flat
// caller-provided workspace tensor, carved by this header.
//
// This header is deliberately CK-free: it only describes sizes and offsets so
// that the pybind layer can expose a size query without pulling CK headers.
#pragma once

#include <torch/extension.h>

#include <array>
#include <cstdint>

namespace aiter {
namespace ck_gdn {

inline constexpr int64_t kHeadDim   = 128;
inline constexpr int64_t kChunkSize = 64;

// Every carved region starts on this boundary. CK kernels use 16B vector
// accesses; 256B also keeps the 128-wide tiles naturally aligned.
inline constexpr int64_t kAlign = 256;

// Smallest allocation handed out for an unused (dummy) region. CK expects a
// valid, non-null pointer even when the corresponding feature is disabled.
inline constexpr int64_t kDummyBytes = 4096;

inline int64_t align_up(int64_t value, int64_t alignment)
{
    return (value + alignment - 1) / alignment * alignment;
}

// Shapes that decide the workspace size. Derived once from the user tensors
// and reused by both the size query and the launch entry.
struct PrefillShape
{
    int64_t t          = 0; // total packed tokens
    int64_t h_qk       = 0;
    int64_t h_v        = 0;
    int64_t sequences  = 1; // logical sequences
    int64_t num_chunks = 0; // sum over sequences of ceil(len / 64)
    bool    varlen     = false; // logical varlen (more than one sequence)
    bool    is_bf16    = true;
};

// Feature switches. Names and defaults follow gdn_example::PrefillArguments.
struct PrefillFlags
{
    bool    use_g                  = true;
    bool    use_gk                 = false;
    bool    use_exp2               = true;
    bool    transpose_state        = false;
    bool    qk_l2norm              = false;
    bool    gate_in_kernel         = false;
    bool    has_dt_bias            = false;
    bool    beta_sigmoid_in_kernel = false;
    bool    output_final_state     = true;
    bool    cp_context             = false;
    int64_t cp_world_size          = 2;
    bool    has_initial_state      = false;
    // Computed by the adapter through gdn_example::select_state_cp_groups().
    int64_t state_cp_groups        = 0;
};

// Flat workspace regions. The order is part of the ABI between the size query
// and the carving helper -- always index through this enum so both stay in
// sync.
enum class PfBuf : int
{
    Gcum = 0,       // float  [t, h_v]
    A,              // dtype  [t, h_v, 64]
    W,              // dtype  [t, h_v, 128]
    U,              // dtype  [t, h_v, 128]
    H,              // dtype  [num_chunks, h_v, 128, 128] (CK internal layout)
    VNew,           // dtype  [t, h_v, 128]
    StateInputWs,   // float  transposed initial-state staging
    StateFinalWs,   // float  transposed final-state staging
    CpGroupA,       // dtype  CP-context grouped-scan staging
    CpGroupB,       // dtype  CP-context grouped-scan staging
    CpGroupStart,   // float  CP-context grouped-scan staging
    CpSummary,      // float  CP-context per-rank summary (h_v,128,256)
    CpAgSummary,    // float  CP-context all-gather summary
    CpState,        // float  CP-context merged state
    QNorm,          // dtype  L2-normalised Q
    KNorm,          // dtype  L2-normalised K
    QRstd,          // float
    KRstd,          // float
    BetaProcessed,  // float  in-kernel beta sigmoid output
    ChunkIndices,   // int64  [num_chunks, 2]
    ChunkOffsets,   // int64  [sequences + 1]
    Dummy,          // neutral pointer for disabled optional inputs
    Count,
};

inline constexpr int kNumPfBuf = static_cast<int>(PfBuf::Count);

// Byte size of every region for the given shape/flags. Disabled regions still
// receive kDummyBytes so that a non-null pointer is always available.
inline std::array<int64_t, kNumPfBuf> prefill_buffer_bytes(const PrefillShape& s,
                                                           const PrefillFlags& f)
{
    // Both supported input types are two bytes wide.
    const int64_t elem_bytes     = 2;
    const int64_t state_elems    = s.sequences * s.h_v * kHeadDim * kHeadDim;
    const int64_t cp_group_elems = f.state_cp_groups > 1
                                       ? f.state_cp_groups * s.h_v * kHeadDim * kHeadDim
                                       : 0;
    const int64_t cp_summary_elems = s.h_v * kHeadDim * 256;

    std::array<int64_t, kNumPfBuf> bytes{};
    for(auto& value : bytes)
        value = kDummyBytes;

    bytes[static_cast<int>(PfBuf::Gcum)] = s.t * s.h_v * sizeof(float);
    bytes[static_cast<int>(PfBuf::A)]    = s.t * s.h_v * kChunkSize * elem_bytes;
    bytes[static_cast<int>(PfBuf::W)]    = s.t * s.h_v * kHeadDim * elem_bytes;
    bytes[static_cast<int>(PfBuf::U)]    = s.t * s.h_v * kHeadDim * elem_bytes;
    bytes[static_cast<int>(PfBuf::H)] =
        s.num_chunks * s.h_v * kHeadDim * kHeadDim * elem_bytes;
    bytes[static_cast<int>(PfBuf::VNew)] = s.t * s.h_v * kHeadDim * elem_bytes;

    if(f.transpose_state)
        bytes[static_cast<int>(PfBuf::StateInputWs)] = state_elems * sizeof(float);
    if(f.transpose_state && f.output_final_state)
        bytes[static_cast<int>(PfBuf::StateFinalWs)] = state_elems * sizeof(float);

    if(f.state_cp_groups > 1)
    {
        bytes[static_cast<int>(PfBuf::CpGroupA)] =
            cp_group_elems * elem_bytes;
        bytes[static_cast<int>(PfBuf::CpGroupB)] =
            cp_group_elems * elem_bytes;
        bytes[static_cast<int>(PfBuf::CpGroupStart)] =
            cp_group_elems * sizeof(float);
    }

    if(f.cp_context)
    {
        bytes[static_cast<int>(PfBuf::CpSummary)] = cp_summary_elems * sizeof(float);
        bytes[static_cast<int>(PfBuf::CpAgSummary)] =
            cp_summary_elems * f.cp_world_size * sizeof(float);
        bytes[static_cast<int>(PfBuf::CpState)] =
            s.h_v * kHeadDim * kHeadDim * sizeof(float);
    }

    if(f.qk_l2norm)
    {
        bytes[static_cast<int>(PfBuf::QNorm)] = s.t * s.h_qk * kHeadDim * elem_bytes;
        bytes[static_cast<int>(PfBuf::KNorm)] = s.t * s.h_qk * kHeadDim * elem_bytes;
        bytes[static_cast<int>(PfBuf::QRstd)] = s.t * s.h_qk * sizeof(float);
        bytes[static_cast<int>(PfBuf::KRstd)] = s.t * s.h_qk * sizeof(float);
    }

    if(f.beta_sigmoid_in_kernel)
        bytes[static_cast<int>(PfBuf::BetaProcessed)] = s.t * s.h_v * sizeof(float);

    bytes[static_cast<int>(PfBuf::ChunkIndices)] =
        s.num_chunks * 2 * static_cast<int64_t>(sizeof(int64_t));
    bytes[static_cast<int>(PfBuf::ChunkOffsets)] =
        (s.sequences + 1) * static_cast<int64_t>(sizeof(int64_t));

    for(auto& value : bytes)
        value = align_up(value, kAlign);
    return bytes;
}

// Total bytes the caller has to provide for the flat workspace tensor.
inline int64_t prefill_workspace_bytes(const PrefillShape& s, const PrefillFlags& f)
{
    const auto bytes = prefill_buffer_bytes(s, f);
    int64_t total    = 0;
    for(const auto value : bytes)
        total += value;
    return total;
}

// Offsets of every region inside the flat workspace. Indexed by PfBuf.
inline std::array<int64_t, kNumPfBuf> prefill_buffer_offsets(const PrefillShape& s,
                                                             const PrefillFlags& f)
{
    const auto bytes = prefill_buffer_bytes(s, f);
    std::array<int64_t, kNumPfBuf> offsets{};
    int64_t cursor = 0;
    for(int i = 0; i < kNumPfBuf; ++i)
    {
        offsets[i] = cursor;
        cursor += bytes[i];
    }
    return offsets;
}

// Typed view of the carved flat workspace.
class PrefillWorkspace
{
    public:
    PrefillWorkspace(uint8_t* base, const std::array<int64_t, kNumPfBuf>& offsets)
        : base_(base), offsets_(offsets)
    {
    }

    template <typename T>
    T* at(PfBuf which) const
    {
        return reinterpret_cast<T*>(base_ + offsets_[static_cast<int>(which)]);
    }

    // Byte offset of a region, used when a CK argument needs an untyped pointer.
    uint8_t* raw(PfBuf which) const { return base_ + offsets_[static_cast<int>(which)]; }

    private:
    uint8_t*                       base_;
    std::array<int64_t, kNumPfBuf> offsets_;
};

} // namespace ck_gdn
} // namespace aiter
