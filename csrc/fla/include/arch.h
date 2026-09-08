// SPDX-License-Identifier: MIT
#pragma once

#include "aiter_hip_common.h"

#include <cstdint>
#include <type_traits>

namespace FLA_NAMESPACE {

using fla_f32x4 = float __attribute__((ext_vector_type(4)));
using fla_f32x2 = float __attribute__((ext_vector_type(2)));
using fla_i32x2 = int32_t __attribute__((ext_vector_type(2)));
using fla_i32x4 = int32_t __attribute__((ext_vector_type(4)));
using fla_u32x4 = uint32_t __attribute__((ext_vector_type(4)));
using fla_u32x2 = uint32_t __attribute__((ext_vector_type(2)));

struct alignas(16) fla_buffer_accessor
{
    fla_i32x4 buffer_res;
    int32_t vofft = 0;

    __device__ __forceinline__ explicit fla_buffer_accessor(const void *ptr)
    {
        auto *buffer_res_ptr = reinterpret_cast<uint64_t *>(&buffer_res);
        buffer_res_ptr[0] = reinterpret_cast<uint64_t>(ptr);
        buffer_res_ptr[1] =
            (uint64_t(0x20000) << 32) | uint64_t(0xFFFFFFFEu);
    }
};

__device__ __forceinline__ __amdgpu_buffer_rsrc_t
fla_make_hcu_buffer_rsrc(const void *ptr)
{
    // The HCU raw buffer builtins take the compiler-private
    // __amdgpu_buffer_rsrc_t type, not a plain int32x4 descriptor.  Keep the
    // descriptor fields identical to fla_buffer_accessor: stride=0,
    // records=0xfffffffe, config=0x00020000.
    return __builtin_amdgcn_make_buffer_rsrc(
        const_cast<void *>(ptr), 0, 0xFFFFFFFEu, 0x00020000u);
}

// Build a raw fla_i32x4 buffer descriptor for direct-to-LDS raw buffer loads
// (__builtin_hcu_raw_buffer_load_lds / fla_buffer_load_dwordx4_to_lds_inline
// below), broadcasting `ptr` through readfirstlane so every lane in the wave
// carries the same SGPR base address.  Callers of this helper already load a
// wave-uniform GMEM base (e.g. the tile-prefetch routines in utils.h), unlike
// fla_buffer_accessor/fla_make_hcu_buffer_rsrc which build a per-lane VGPR
// descriptor.  Uses the same records/config fields as fla_buffer_accessor so
// there is a single OOB-bound convention across all buffer descriptors in
// this file.
__device__ __forceinline__ fla_i32x4
fla_make_uniform_buffer_rsrc(const void *ptr)
{
    struct PtrWrapper {
        uint32_t former;
        uint32_t latter;
    };
    PtrWrapper glob_ptr;
    *reinterpret_cast<uint64_t *>(&glob_ptr) = reinterpret_cast<uint64_t>(ptr);

    fla_u32x4 global_addr = {0};
    global_addr[0] = __builtin_amdgcn_readfirstlane(glob_ptr.former);
    global_addr[1] = __builtin_amdgcn_readfirstlane(glob_ptr.latter);
    global_addr[2] = 0xFFFFFFFEu;
    global_addr[3] = 0x00020000u;
    return ck_tile::bit_cast<fla_i32x4>(global_addr);
}

// ---------------------------------------------------------------------------
// Global memory access (raw buffer load/store).
//
// OOB handling is delegated entirely to the hardware: both fla_buffer_accessor
// and fla_make_hcu_buffer_rsrc build a descriptor with records=0xFFFFFFFE, so
// passing voffset=-1 (0xFFFFFFFF once read as unsigned) is the only offset
// that falls outside the descriptor's range.  Callers that need a
// conditionally-valid access simply select `valid ? byte_offset : -1` before
// calling in; no software masking is done here.  DWORD_CNT selects the
// vectorization width (1/2/4 dwords) and USE_ASM selects the codegen path:
// hand-written inline asm (default, gives the caller explicit control over
// waitcnt placement) or the compiler's __builtin_hcu_raw_buffer_* intrinsics.
// ---------------------------------------------------------------------------

template <int DWORD_CNT>
struct fla_dword_vec_traits;

template <>
struct fla_dword_vec_traits<1>
{
    using type = uint32_t;
};

template <>
struct fla_dword_vec_traits<2>
{
    using type = fla_u32x2;
};

template <>
struct fla_dword_vec_traits<4>
{
    using type = fla_u32x4;
};

template <int DWORD_CNT>
using fla_dword_vec_t = typename fla_dword_vec_traits<DWORD_CNT>::type;

template <int DWORD_CNT, bool USE_ASM = true>
__device__ __forceinline__ fla_dword_vec_t<DWORD_CNT>
fla_buffer_load_vgpr(const void *base_ptr, const int32_t voffset)
{
    static_assert(DWORD_CNT == 1 || DWORD_CNT == 2 || DWORD_CNT == 4,
                  "fla_buffer_load_vgpr supports 1/2/4 dword loads");
    using Vec = fla_dword_vec_t<DWORD_CNT>;
#if defined(__gfx928__) || defined(__gfx936__) || defined(__gfx938__)
    if constexpr (USE_ASM) {
        fla_buffer_accessor ptr(base_ptr);
        Vec raw;
        const int32_t src_voffset = ptr.vofft + voffset;
        if constexpr (DWORD_CNT == 1) {
            asm volatile("buffer_load_dword %0, %1, %2, 0 offen offset:0;\n\t"
                         : "=v"(raw)
                         : "v"(src_voffset), "s"(ptr.buffer_res)
                         : "memory");
        } else if constexpr (DWORD_CNT == 2) {
            asm volatile("buffer_load_dwordx2 %0, %1, %2, 0 offen offset:0;\n\t"
                         : "=v"(raw)
                         : "v"(src_voffset), "s"(ptr.buffer_res)
                         : "memory");
        } else {
            asm volatile("buffer_load_dwordx4 %0, %1, %2, 0 offen offset:0;\n\t"
                         : "=v"(raw)
                         : "v"(src_voffset), "s"(ptr.buffer_res)
                         : "memory");
        }
        return raw;
    } else {
        const __amdgpu_buffer_rsrc_t rsrc = fla_make_hcu_buffer_rsrc(base_ptr);
        if constexpr (DWORD_CNT == 1) {
            return __builtin_hcu_raw_buffer_load_b32(rsrc, voffset, 0, 0);
        } else if constexpr (DWORD_CNT == 2) {
            return __builtin_hcu_raw_buffer_load_b64(rsrc, voffset, 0, 0);
        } else {
            return __builtin_hcu_raw_buffer_load_b128(rsrc, voffset, 0, 0);
        }
    }
#else
    (void)base_ptr;
    (void)voffset;
    return Vec{};
#endif
}

template <int DWORD_CNT, bool USE_ASM = true>
__device__ __forceinline__ void
fla_buffer_store_vgpr(void *base_ptr, const int32_t voffset,
                      const fla_dword_vec_t<DWORD_CNT> value)
{
    static_assert(DWORD_CNT == 1 || DWORD_CNT == 2 || DWORD_CNT == 4,
                  "fla_buffer_store_vgpr supports 1/2/4 dword stores");
#if defined(__gfx928__) || defined(__gfx936__) || defined(__gfx938__)
    if constexpr (USE_ASM) {
        fla_buffer_accessor ptr(base_ptr);
        const int32_t dst_voffset = ptr.vofft + voffset;
        if constexpr (DWORD_CNT == 1) {
            asm volatile("buffer_store_dword %0, %1, %2, 0 offen offset:0\n\t"
                         "s_nop 2"
                         :
                         : "v"(value), "v"(dst_voffset), "s"(ptr.buffer_res)
                         : "memory");
        } else if constexpr (DWORD_CNT == 2) {
            asm volatile("buffer_store_dwordx2 %0, %1, %2, 0 offen offset:0\n\t"
                         "s_nop 2"
                         :
                         : "v"(value), "v"(dst_voffset), "s"(ptr.buffer_res)
                         : "memory");
        } else {
            asm volatile("buffer_store_dwordx4 %0, %1, %2, 0 offen offset:0\n\t"
                         "s_nop 2"
                         :
                         : "v"(value), "v"(dst_voffset), "s"(ptr.buffer_res)
                         : "memory");
        }
    } else {
        const __amdgpu_buffer_rsrc_t rsrc = fla_make_hcu_buffer_rsrc(base_ptr);
        if constexpr (DWORD_CNT == 1) {
            __builtin_hcu_raw_buffer_store_b32(value, rsrc, voffset, 0, 0);
        } else if constexpr (DWORD_CNT == 2) {
            __builtin_hcu_raw_buffer_store_b64(value, rsrc, voffset, 0, 0);
        } else {
            __builtin_hcu_raw_buffer_store_b128(value, rsrc, voffset, 0, 0);
        }
    }
#else
    (void)base_ptr;
    (void)voffset;
    (void)value;
#endif
}

__device__ __forceinline__ void
fla_buffer_store_dwordx4_vgpr(void *base_ptr, const int32_t voffset,
                              const fla_u32x4 value)
{
    fla_buffer_store_vgpr<4>(base_ptr, voffset, value);
}

// Direct-to-LDS raw buffer load.  Same instruction family as
// fla_buffer_load_vgpr above, but the destination is LDS (via m0) instead of
// a VGPR, so the caller supplies an already-built buffer descriptor plus the
// per-wave LDS target address.  m0 carries the per-wave LDS destination and
// offset_v is the per-lane GMEM byte offset.  VMEM completion is left under
// the caller's explicit waitcnt/barrier sites, matching
// fla_buffer_load_vgpr/fla_buffer_store_vgpr.
__device__ __forceinline__ void
fla_buffer_load_dwordx4_to_lds_inline(const fla_i32x4 buffer_rsrc,
                                      const int target_addr,
                                      const int offset_v)
{
#if defined(__gfx936__) || defined(__gfx938__)
    asm volatile(
        "s_mov_b32 m0, %1\n\t"
        "buffer_load_dwordx4 %0, %2, 0, offen offset:0, lds\n\t"
        :
        : "v"(offset_v), "s"(target_addr), "s"(buffer_rsrc)
        : "memory");
#else
    (void)buffer_rsrc;
    (void)target_addr;
    (void)offset_v;
#endif
}

__device__ __forceinline__ fla_u32x4
fla_buffer_load_dwordx4_vgpr_inline(const fla_i32x4 buffer_rsrc,
                                    const int32_t voffset)
{
#if defined(__gfx928__) || defined(__gfx936__) || defined(__gfx938__)
    fla_u32x4 raw;
    asm volatile("buffer_load_dwordx4 %0, %1, %2, 0 offen offset:0\n\t"
                 : "=v"(raw)
                 : "v"(voffset), "s"(buffer_rsrc)
                 : "memory");
    return raw;
#else
    (void)buffer_rsrc;
    (void)voffset;
    return fla_u32x4{0, 0, 0, 0};
#endif
}

__device__ __forceinline__ void compiler_sched_barrier()
{
    __builtin_amdgcn_sched_barrier(0);
}

// Pin VMEM waitcnt sites: sched_barrier before/after s_waitcnt vmcnt so
// buffer_load/store cannot be reordered across the age-model boundary.
template <int Vmcnt>
__device__ __forceinline__ void wait_vmcnt()
{
    static_assert(Vmcnt >= 0, "vmcnt must be non-negative");
    compiler_sched_barrier();
    asm volatile("s_waitcnt vmcnt(%0)\n\t" : : "n"(Vmcnt) : "memory");
    compiler_sched_barrier();
}

template <int Lgkmcnt>
__device__ __forceinline__ void wait_lgkmcnt_dep(fla_u32x4 &dep0,
                                                 fla_u32x4 &dep1)
{
    static_assert(Lgkmcnt >= 0, "lgkmcnt must be non-negative");
    asm volatile("s_waitcnt lgkmcnt(%2)\n\t"
                 : "+v"(dep0), "+v"(dep1)
                 : "n"(Lgkmcnt)
                 : "memory");
}

template <int Lgkmcnt>
__device__ __forceinline__ void wait_lgkmcnt_dep(fla_u32x4 &dep0,
                                                 fla_u32x4 &dep1,
                                                 fla_u32x4 &dep2)
{
    static_assert(Lgkmcnt >= 0, "lgkmcnt must be non-negative");
    asm volatile("s_waitcnt lgkmcnt(%3)\n\t"
                 : "+v"(dep0), "+v"(dep1), "+v"(dep2)
                 : "n"(Lgkmcnt)
                 : "memory");
}

template <int Lgkmcnt>
__device__ __forceinline__ void wait_lgkmcnt_dep(fla_u32x4 &dep0,
                                                 fla_u32x4 &dep1,
                                                 fla_u32x4 &dep2,
                                                 fla_u32x4 &dep3)
{
    static_assert(Lgkmcnt >= 0, "lgkmcnt must be non-negative");
    asm volatile("s_waitcnt lgkmcnt(%4)\n\t"
                 : "+v"(dep0), "+v"(dep1), "+v"(dep2), "+v"(dep3)
                 : "n"(Lgkmcnt)
                 : "memory");
}

// Keep LDS operations and the CTA barrier visible to LLVM so it can derive
// only the required lgkmcnt waits.  This is preferable to composing an
// intrinsic DS access with a second, manually encoded waitcnt.
__device__ __forceinline__ void fla_lds_barrier()
{
    __builtin_amdgcn_s_barrier();
}

// Same sched fence as wait_vmcnt, then lgkmcnt(0)+s_barrier in one asm block
// (analogous to: sched_barrier(); asm("vmcnt(N); barrier"); sched_barrier()).
template <int Vmcnt>
__device__ __forceinline__ void wait_vmcnt_lgkmcnt0_barrier()
{
    static_assert(Vmcnt >= 0, "vmcnt must be non-negative");
    compiler_sched_barrier();
    asm volatile("s_waitcnt vmcnt(%0)\n\t"
                 "s_waitcnt lgkmcnt(0)\n\t"
                 "s_barrier\n\t"
                 :
                 : "n"(Vmcnt)
                 : "memory");
    compiler_sched_barrier();
}

template <int Vmcnt>
__device__ __forceinline__ void wait_vmcnt_barrier()
{
    static_assert(Vmcnt >= 0, "vmcnt must be non-negative");
    compiler_sched_barrier();
    asm volatile("s_waitcnt vmcnt(%0)\n\t"
                 "s_barrier\n\t"
                 :
                 : "n"(Vmcnt)
                 : "memory");
    compiler_sched_barrier();
}

__device__ __forceinline__ void wait_lgkmcnt0_barrier()
{
    asm volatile("s_waitcnt lgkmcnt(0)\n\t"
                 "s_barrier\n\t"
                 :
                 :
                 : "memory");
}

__device__ __forceinline__ void wait_all_and_barrier()
{
    wait_vmcnt_lgkmcnt0_barrier<0>();
}

template <typename Element>
struct fla_dtype_traits
{
    static constexpr bool is_fp16 = std::is_same_v<Element, ck_tile::fp16_t>;
    static constexpr bool is_bf16 = std::is_same_v<Element, ck_tile::bf16_t>;
    static constexpr bool supported = is_fp16 || is_bf16;

    using native_t = typename ck_tile::native_t<Element>::type;
    using vec4_t = ck_tile::ext_vector_t<Element, 4>;
};

// Four fp16/bf16 elements occupy two dwords; thin wrapper over
// fla_buffer_load_vgpr<2> that returns them typed as Element instead of raw
// dwords.
template <typename Element, bool USE_ASM = true>
__device__ __forceinline__ typename fla_dtype_traits<Element>::vec4_t
fla_buffer_load_element_v4_vgpr(const void *base_ptr, const int32_t voffset)
{
    static_assert(fla_dtype_traits<Element>::supported,
                  "FLA buffer_load_element_v4 supports fp16 and bf16 only");
    using Vec4 = typename fla_dtype_traits<Element>::vec4_t;
    const fla_u32x2 raw = fla_buffer_load_vgpr<2, USE_ASM>(base_ptr, voffset);
    return ck_tile::bit_cast<Vec4>(raw);
}

template <typename Element>
__device__ __forceinline__ uint16_t
fla_element_bits_from_float(const float value)
{
    const Element element = ck_tile::type_convert<Element>(value);
    return ck_tile::bit_cast<uint16_t>(element);
}

template <typename Element>
__device__ __forceinline__ uint32_t
fla_pack_element_x2_bits(const float lo, const float hi)
{
    return uint32_t(fla_element_bits_from_float<Element>(lo)) |
           (uint32_t(fla_element_bits_from_float<Element>(hi)) << 16);
}

__device__ __forceinline__ fla_f32x2
fla_pk_mul_f32(const fla_f32x2 a, const fla_f32x2 b)
{
#if defined(__gfx936__) || defined(__gfx938__)
    fla_f32x2 out;
    asm volatile("v_pk_mul_f32 %0, %1, %2"
                 : "=v"(out)
                 : "v"(a), "v"(b));
    return out;
#else
    return fla_f32x2{a[0] * b[0], a[1] * b[1]};
#endif
}

__device__ __forceinline__ fla_f32x2
fla_pk_fma_f32(const fla_f32x2 a, const fla_f32x2 b, const fla_f32x2 c)
{
#if defined(__gfx936__) || defined(__gfx938__)
    fla_f32x2 out;
    asm volatile("v_pk_fma_f32 %0, %1, %2, %3"
                 : "=v"(out)
                 : "v"(a), "v"(b), "v"(c));
    return out;
#else
    return fla_f32x2{a[0] * b[0] + c[0], a[1] * b[1] + c[1]};
#endif
}

// Scale all four lanes of a packed fp32x4 in place via two packed multiplies.
__device__ __forceinline__ void
fla_scale_v4_pairs(fla_f32x4 &value, const float scale)
{
    const fla_f32x2 scale_pair = {scale, scale};
    const fla_f32x2 lo = fla_pk_mul_f32(
        fla_f32x2{value[0], value[1]}, scale_pair);
    const fla_f32x2 hi = fla_pk_mul_f32(
        fla_f32x2{value[2], value[3]}, scale_pair);
    value = fla_f32x4{lo[0], lo[1], hi[0], hi[1]};
}

template <typename Element>
__device__ __forceinline__ uint32_t
fla_pack_element_x2_bits(const fla_f32x2 values)
{
#if defined(__gfx938__)
    uint32_t out;
    if constexpr (fla_dtype_traits<Element>::is_fp16) {
        asm volatile("v_cvt_pk_f16_f32 %0, %1, %2"
                     : "=v"(out)
                     : "v"(values[0]), "v"(values[1]));
    } else {
        asm volatile("v_cvt_pk_bf16_f32 %0, %1, %2"
                     : "=v"(out)
                     : "v"(values[0]), "v"(values[1]));
    }
    return out;
#else
    return fla_pack_element_x2_bits<Element>(values[0], values[1]);
#endif
}

template <typename Element>
__device__ __forceinline__ typename fla_dtype_traits<Element>::vec4_t
fla_pack_f32x4_to_element_vec4(const fla_f32x4 values)
{
    using ElementVec4 = typename fla_dtype_traits<Element>::vec4_t;
    const fla_u32x2 packed = {
        fla_pack_element_x2_bits<Element>(fla_f32x2{values[0], values[1]}),
        fla_pack_element_x2_bits<Element>(fla_f32x2{values[2], values[3]})};
    return ck_tile::bit_cast<ElementVec4>(packed);
}

template <typename Element>
__device__ __forceinline__ typename fla_dtype_traits<Element>::vec4_t
fla_vec4_from_pack(const fla_u32x4 pack, const int element_offset)
{
    using Traits = fla_dtype_traits<Element>;
    using Native = typename Traits::native_t;
    using Vec4 = typename Traits::vec4_t;

    Vec4 out = {};
    const Native *src = reinterpret_cast<const Native *>(&pack);
#pragma unroll
    for (int s = 0; s < 4; ++s) {
        out[s] = src[element_offset + s];
    }
    return out;
}

// Pack four (lo, hi) fp32 pairs into a 128-bit dword vector of Element bits;
// the natural v8 counterpart of fla_vec4_from_pack above.
template <typename Element>
__device__ __forceinline__ fla_u32x4
fla_pack_v8_from_f32(const fla_f32x4 lo, const fla_f32x4 hi)
{
    return fla_u32x4{
        fla_pack_element_x2_bits<Element>(fla_f32x2{lo[0], lo[1]}),
        fla_pack_element_x2_bits<Element>(fla_f32x2{lo[2], lo[3]}),
        fla_pack_element_x2_bits<Element>(fla_f32x2{hi[0], hi[1]}),
        fla_pack_element_x2_bits<Element>(fla_f32x2{hi[2], hi[3]}),
    };
}

// Symmetric typed-store counterparts of fla_buffer_load_element_v4_vgpr
// above: pack fp32 pairs into Element bits, then issue a raw dword/dwordx4
// buffer store.  As with all fla_buffer_store_vgpr callers, OOB is expressed
// by the caller passing voffset=-1; there is no separate "_no_oob" variant.
template <typename Element>
__device__ __forceinline__ void
fla_buffer_store_element_v4_vgpr(Element *dst_base, const int32_t voffset,
                                 const fla_f32x2 lo, const fla_f32x2 hi)
{
    const fla_u32x2 packed = {
        fla_pack_element_x2_bits<Element>(lo),
        fla_pack_element_x2_bits<Element>(hi),
    };
    fla_buffer_store_vgpr<2>(dst_base, voffset, packed);
}

// Eight fp16/bf16 elements occupy four dwords; thin wrapper over
// fla_buffer_store_vgpr<4>, symmetric to a hypothetical v8 load built on
// fla_buffer_load_vgpr<4> (see fla_buffer_load_element_v8_vgpr below).
template <typename Element>
__device__ __forceinline__ void
fla_buffer_store_element_v8_vgpr(Element *dst_base, const int32_t voffset,
                                 const fla_f32x4 lo, const fla_f32x4 hi)
{
    fla_buffer_store_vgpr<4>(
        dst_base, voffset, fla_pack_v8_from_f32<Element>(lo, hi));
}

// Eight fp16/bf16 elements occupy four dwords; thin wrapper over
// fla_buffer_load_vgpr<4> that returns them typed as Element instead of raw
// dwords.  Replaces the legacy CK-predicated load path
// (ck_tile::amd_buffer_load_invalid_element_return_zero) with the same
// hardware-descriptor OOB convention used everywhere else in this file:
// the caller passes voffset=-1 for an out-of-bounds access.
template <typename Element, bool USE_ASM = true>
__device__ __forceinline__ fla_u32x4
fla_buffer_load_element_v8_vgpr(const void *base_ptr, const int32_t voffset)
{
    static_assert(fla_dtype_traits<Element>::supported,
                  "FLA buffer_load_element_v8 supports fp16 and bf16 only");
    return fla_buffer_load_vgpr<4, USE_ASM>(base_ptr, voffset);
}

// MMAC and LDS matrix-read wrappers keep the fp16/bf16 selection local.  The
// kernel can then express one algorithm path without duplicating dtype branches.
template <typename Element>
__device__ __forceinline__ fla_f32x4 fla_mmac_f32_16x16x16(
    const typename fla_dtype_traits<Element>::vec4_t a,
    const typename fla_dtype_traits<Element>::vec4_t b,
    const fla_f32x4 c)
{
    static_assert(fla_dtype_traits<Element>::supported,
                  "FLA MMAC supports fp16 and bf16 only");
#if defined(__gfx928__) || defined(__gfx936__) || defined(__gfx938__)
    if constexpr (fla_dtype_traits<Element>::is_fp16) {
        return __builtin_hcu_mmac_f32_16x16x16_f16(a, b, c);
    } else {
        return __builtin_hcu_mmac_f32_16x16x16_bf16(a, b, c);
    }
#else
    return c;
#endif
}

template <typename Element>
__device__ __forceinline__ void fla_mmac_f32_16x16x16_accumulate(
    const typename fla_dtype_traits<Element>::vec4_t a,
    const typename fla_dtype_traits<Element>::vec4_t b, fla_f32x4 &c)
{
    c = fla_mmac_f32_16x16x16<Element>(a, b, c);
}

// gfx938 LIT keeps the A/B lane distribution unchanged and makes the four C
// values lane-local and contiguous along N.  Both fp16 and bf16 use the same
// lane/dataflow contract; the input type selects the corresponding builtin.
template <typename Element>
__device__ __forceinline__ fla_f32x4 fla_mmac_f32_16x16x16_lit(
    const typename fla_dtype_traits<Element>::vec4_t a,
    const typename fla_dtype_traits<Element>::vec4_t b,
    const fla_f32x4 c)
{
    static_assert(fla_dtype_traits<Element>::supported,
                  "FLA LIT MMAC supports fp16 and bf16 only");
#if defined(__gfx938__)
    if constexpr (fla_dtype_traits<Element>::is_fp16) {
        return __builtin_hcu_mmac_f32_16x16x16_f16_lit_lts(
            a, b, c, true, false);
    } else {
        return __builtin_hcu_mmac_f32_16x16x16_bf16_lit_lts(
            a, b, c, true, false);
    }
#else
    return c;
#endif
}

template <typename Element>
__device__ __forceinline__ fla_f32x4 fla_mmac_f32_16x16x16_lit_lts(
    const typename fla_dtype_traits<Element>::vec4_t a,
    const typename fla_dtype_traits<Element>::vec4_t b,
    const fla_f32x4 c)
{
    static_assert(fla_dtype_traits<Element>::supported,
                  "FLA LIT/LTS MMAC supports fp16 and bf16 only");
#if defined(__gfx938__)
    if constexpr (fla_dtype_traits<Element>::is_fp16) {
        return __builtin_hcu_mmac_f32_16x16x16_f16_lit_lts(
            a, b, c, true, true);
    } else {
        return __builtin_hcu_mmac_f32_16x16x16_bf16_lit_lts(
            a, b, c, true, true);
    }
#else
    return c;
#endif
}

template <typename Element>
__device__ __forceinline__ fla_f32x4 fla_mmac_f32_16x16x16_trans_c(
    const typename fla_dtype_traits<Element>::vec4_t a,
    const typename fla_dtype_traits<Element>::vec4_t b,
    const fla_f32x4 c)
{
    static_assert(fla_dtype_traits<Element>::supported,
                  "FLA MMAC supports fp16 and bf16 only");
#if defined(__gfx928__) || defined(__gfx936__) || defined(__gfx938__)
    if constexpr (fla_dtype_traits<Element>::is_fp16) {
        return __builtin_hcu_mmac_f32_16x16x16_f16(b, a, c);
    } else {
        return __builtin_hcu_mmac_f32_16x16x16_bf16(b, a, c);
    }
#else
    return c;
#endif
}

template <typename Element>
__device__ __forceinline__ fla_u32x4
fla_ds_read_m32x16_alt(Element *src_ptr)
{
    static_assert(fla_dtype_traits<Element>::supported,
                  "FLA ds_read_m32x16 supports fp16 and bf16 only");
#if defined(__gfx928__) || defined(__gfx936__) || defined(__gfx938__)
    if constexpr (fla_dtype_traits<Element>::is_fp16) {
        const auto reg = __builtin_hcu_ds_read_m32x16_f16_alt(
            (__attribute__((address_space(3))) __fp16 *)src_ptr);
        return ck_tile::bit_cast<fla_u32x4>(reg);
    } else {
        const auto reg = __builtin_hcu_ds_read_m32x16_bf16_alt(
            (__attribute__((address_space(3))) short *)src_ptr);
        return ck_tile::bit_cast<fla_u32x4>(reg);
    }
#else
    return fla_u32x4{0, 0, 0, 0};
#endif
}

template <typename Element>
__device__ __forceinline__ fla_u32x4
fla_ds_read_m32x16_alt_asm(Element *src_ptr)
{
    static_assert(fla_dtype_traits<Element>::supported,
                  "FLA ds_read_m32x16 asm supports fp16 and bf16 only");
#if defined(__gfx928__) || defined(__gfx936__) || defined(__gfx938__)
    fla_u32x4 out;
    const uint32_t lds_addr =
        static_cast<uint32_t>(reinterpret_cast<uintptr_t>(src_ptr));
    asm volatile("ds_read_m32x16_b16_alt %0, %1 offset:0\n\t"
                 : "=&v"(out)
                 : "v"(lds_addr)
                 : "memory");
    return out;
#else
    (void)src_ptr;
    return fla_u32x4{0, 0, 0, 0};
#endif
}

template <typename Element>
__device__ __forceinline__ fla_u32x4
fla_ds_read_m32x16(Element *src_ptr)
{
    static_assert(fla_dtype_traits<Element>::supported,
                  "FLA ds_read_m32x16 supports fp16 and bf16 only");
#if defined(__gfx928__) || defined(__gfx936__) || defined(__gfx938__)
    if constexpr (fla_dtype_traits<Element>::is_fp16) {
        const auto reg = __builtin_hcu_ds_read_m32x16_f16(
            (__attribute__((address_space(3))) __fp16 *)src_ptr);
        return ck_tile::bit_cast<fla_u32x4>(reg);
    } else {
        const auto reg = __builtin_hcu_ds_read_m32x16_bf16(
            (__attribute__((address_space(3))) short *)src_ptr);
        return ck_tile::bit_cast<fla_u32x4>(reg);
    }
#else
    return fla_u32x4{0, 0, 0, 0};
#endif
}

template <typename Element>
__device__ __forceinline__ fla_u32x4
fla_ds_read_m32x16_asm(Element *src_ptr)
{
    static_assert(fla_dtype_traits<Element>::supported,
                  "FLA ds_read_m32x16 asm supports fp16 and bf16 only");
#if defined(__gfx928__) || defined(__gfx936__) || defined(__gfx938__)
    fla_u32x4 out;
    const uint32_t lds_addr =
        static_cast<uint32_t>(reinterpret_cast<uintptr_t>(src_ptr));
    asm volatile("ds_read_m32x16_b16 %0, %1 offset:0\n\t"
                 : "=&v"(out)
                 : "v"(lds_addr)
                 : "memory");
    return out;
#else
    (void)src_ptr;
    return fla_u32x4{0, 0, 0, 0};
#endif
}

template <typename Element>
__device__ __forceinline__ fla_u32x4
fla_ds_read_b128(Element *src_ptr)
{
    return *reinterpret_cast<fla_u32x4 *>(src_ptr);
}

template <typename Element>
__device__ __forceinline__ fla_u32x4
fla_ds_read_b128_asm(Element *src_ptr)
{
#if defined(__gfx928__) || defined(__gfx936__) || defined(__gfx938__)
    fla_u32x4 out;
    const uint32_t lds_addr =
        static_cast<uint32_t>(reinterpret_cast<uintptr_t>(src_ptr));
    asm volatile("ds_read_b128 %0, %1 offset:0\n\t"
                 : "=&v"(out)
                 : "v"(lds_addr)
                 : "memory");
    return out;
#else
    (void)src_ptr;
    return fla_u32x4{0, 0, 0, 0};
#endif
}

__device__ __forceinline__ void fla_ds_write_b32(const uint32_t lds_addr,
                                                 const uint32_t data)
{
#if defined(__gfx928__) || defined(__gfx936__) || defined(__gfx938__)
    asm volatile("ds_write_b32 %0, %1 offset:0\n\t"
                 :
                 : "v"(lds_addr), "v"(data)
                 : "memory");
#else
    (void)lds_addr;
    (void)data;
#endif
}

template <typename Element>
__device__ __forceinline__ void
fla_ds_write_b32_at(Element *lds_base, const int elem_offset,
                    const uint32_t data)
{
    const uint32_t lds_addr = static_cast<uint32_t>(
        reinterpret_cast<uintptr_t>(lds_base + elem_offset));
    fla_ds_write_b32(lds_addr, data);
}

__device__ __forceinline__ uint32_t
fla_ds_bpermute_u32(const int byte_offset, const uint32_t value)
{
#if defined(__gfx928__) || defined(__gfx936__) || defined(__gfx938__)
    const int32_t raw = __builtin_amdgcn_ds_bpermute(
        byte_offset, ck_tile::bit_cast<int32_t>(value));
    return ck_tile::bit_cast<uint32_t>(raw);
#else
    (void)byte_offset;
    return value;
#endif
}

}  // namespace FLA_NAMESPACE
