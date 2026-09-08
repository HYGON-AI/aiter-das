// SPDX-License-Identifier: MIT
#pragma once

#include "aiter_hip_common.h"   // ck_tile::{fp16_t, bf16_t}

////////////////////////////////////////////////////////////////////////////////////////////////////
// Lightweight static-switch macros for kernel dispatch.
//
//   BOOL_SWITCH(cond, NAME, [&]{ use<NAME>(...); });
//
// Expands a runtime bool into a compile-time `constexpr static bool NAME` inside
// each lambda branch so the kernel template parameter is known at compile time.
////////////////////////////////////////////////////////////////////////////////////////////////////

#define BOOL_SWITCH(COND, CONST_NAME, ...)      \
    [&] {                                       \
        if (COND) {                             \
            constexpr static bool CONST_NAME = true;  \
            return __VA_ARGS__();               \
        } else {                                \
            constexpr static bool CONST_NAME = false; \
            return __VA_ARGS__();               \
        }                                       \
    }()

// FIXED_TRUE_SWITCH(COND, NAME, MSG, ...)
//
// Same shape as BOOL_SWITCH, but only emits the `NAME=true` template instance.
// Use when a flag is logically templated for future expansion but only the
// `true` branch has a real kernel implementation today. The runtime check
// rejects callers that pass `false`. When the `false` branch lands, swap this
// macro for BOOL_SWITCH at the call site — no other code needs to change.
#define FIXED_TRUE_SWITCH(COND, CONST_NAME, MSG, ...)                          \
    [&] {                                                                      \
        TORCH_CHECK((COND), MSG);                                              \
        constexpr static bool CONST_NAME = true;                               \
        return __VA_ARGS__();                                                  \
    }()

// FIXED_FALSE_SWITCH — symmetric counterpart for cases where only the
// `NAME=false` branch is currently wired up.
#define FIXED_FALSE_SWITCH(COND, CONST_NAME, MSG, ...)                         \
    [&] {                                                                      \
        TORCH_CHECK(!(COND), MSG);                                             \
        constexpr static bool CONST_NAME = false;                              \
        return __VA_ARGS__();                                                  \
    }()

#ifdef FLASHATTENTION_DISABLE_UNEVEN_K
#define EVENK_SWITCH(COND, CONST_NAME, ...)     \
    [&] {                                       \
        constexpr static bool CONST_NAME = true;\
        return __VA_ARGS__();                   \
    }()
#else
#define EVENK_SWITCH BOOL_SWITCH
#endif

// FP16_SWITCH: lifts runtime dtype to compile-time `elem_type`.
//   COND == true  =>  elem_type = ck_tile::fp16_t
//   COND == false =>  elem_type = ck_tile::bf16_t
#define FP16_SWITCH(COND, ...)                  \
    [&] {                                       \
        if (COND) {                             \
            using elem_type = ck_tile::fp16_t;  \
            return __VA_ARGS__();               \
        } else {                                \
            using elem_type = ck_tile::bf16_t;  \
            return __VA_ARGS__();               \
        }                                       \
    }()

// INDEX_SWITCH: lifts varlen IndexT for cu_seqlens only.
//   COND == true  =>  IndexT = int64_t  (torch.long)
//   COND == false =>  IndexT = int32_t  (torch.int32)
// chunk_indices is host-side NT only (not switched).
// chunk_offsets is always int64 and is not switched here.
#define INDEX_SWITCH(COND, IndexT, ...)         \
    [&] {                                       \
        if (COND) {                             \
            using IndexT = int64_t;             \
            return __VA_ARGS__();               \
        } else {                                \
            using IndexT = int32_t;             \
            return __VA_ARGS__();               \
        }                                       \
    }()

// HEADDIM_SWITCH: round runtime head dim up to the next supported template instantiation.
#define HEADDIM_SWITCH(HEADDIM, ...)            \
    [&] {                                       \
        if      (HEADDIM <=  32) { constexpr static int kHeadDim =  32; return __VA_ARGS__(); } \
        else if (HEADDIM <=  64) { constexpr static int kHeadDim =  64; return __VA_ARGS__(); } \
        else if (HEADDIM <=  96) { constexpr static int kHeadDim =  96; return __VA_ARGS__(); } \
        else if (HEADDIM <= 128) { constexpr static int kHeadDim = 128; return __VA_ARGS__(); } \
        else if (HEADDIM <= 192) { constexpr static int kHeadDim = 192; return __VA_ARGS__(); } \
        else if (HEADDIM <= 256) { constexpr static int kHeadDim = 256; return __VA_ARGS__(); } \
    }()

// HEADDIM_KV_SWITCH: jointly select kHeadDimK / kHeadDimV.
// Currently only (128, 128) is wired; extend as more instances land.
#define HEADDIM_KV_SWITCH(HEADDIM_K, HEADDIM_V, ...)                  \
    [&] {                                                             \
        if (HEADDIM_K <= 128 && HEADDIM_V <= 128) {                   \
            constexpr static int kHeadDim_K = 128;                    \
            constexpr static int kHeadDim_V = 128;                    \
            return __VA_ARGS__();                                     \
        } else {                                                      \
            TORCH_CHECK(false, "chunk_gated_delta_rule_fwd: only "    \
                               "HEADDIM_K==HEADDIM_V==128 is supported"); \
        }                                                             \
    }()
