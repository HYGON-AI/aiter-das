// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
//
// K2 的 global→LDS 直写：kd/qd 与 kr|gt 合并区各一条发射入口（只发不等，
// 落地与跨 wave 可见性由调用点的等待 + CTA barrier 收口）。

#ifndef FLASH_KDA_K2_LOAD_CUH
#define FLASH_KDA_K2_LOAD_CUH

#include "flash_kda_k2_common.cuh"

namespace
{

    // kd/qd 的 global→LDS 直写：每 lane 一条 16 B 请求，写进本 wave 的 LDS 切片。
    // 地址契约：m0 放 wave 均匀的 LDS 切片基址，per-lane 16 B 细分进 voffset，
    // chunk 基址（wave 均匀）进 soffset。
    template <int Waves>
    __device__ __forceinline__ void issue_kdqd_to_lds(
        int tid, int64_t workspace_chunk_index,
        const u16 *ws_kd, const u16 *ws_qd, u16 *s_kd_dst, u16 *s_qd_dst)
    {
#if defined(__gfx936__) || defined(__gfx938__) || defined(__gfx946__)
        constexpr int kCopies = (8 * kTile * kTile) / 8; // 256 次 16 B 拷贝
        const int wave = tid >> 6;
        const vec4_u32 rsrc_kd = kda_c16_make_buffer_rsrc(ws_kd);
        const vec4_u32 rsrc_qd = kda_c16_make_buffer_rsrc(ws_qd);
        const unsigned int soff_kdqd =
            static_cast<unsigned int>(workspace_chunk_index * kKdqdStrideU16 * 2);
#pragma unroll
        for (int i = tid; i < kCopies; i += Waves * 64)
        {
            const int it = i / (Waves * 64);
            const unsigned int lds_slice = static_cast<unsigned int>((wave + it * Waves) * 1024);
            const int voff_bytes = kda_c16_kdqd_src16_byte(i);
            kda_c16_asm::buffer_load_dwordx4_lds(s_kd_dst, rsrc_kd, lds_slice, soff_kdqd,
                                                 voff_bytes);
            kda_c16_asm::buffer_load_dwordx4_lds(s_qd_dst, rsrc_qd, lds_slice, soff_kdqd,
                                                 voff_bytes);
        }
#else
        (void)tid;
        (void)workspace_chunk_index;
        (void)ws_kd;
        (void)ws_qd;
        (void)s_kd_dst;
        (void)s_qd_dst;
#endif
    }

    // kr(4 KiB) + gt(512 B) 合并区的协作直写，每代每 wave 两条请求：
    //   kr 段 4096 B：每 wave 1 KiB 片、每 lane 16 B；
    //   gt 段 512 B：每 wave 128 B、仅 lane<8 执行。
    // LDS 落点 = 区基址 + 该线程在段内的字节偏移，global 地址 = chunk 基址 + 同一偏移
    // （K1 已按 K2 的消费布局写好，故是纯拷贝）。
    template <int Waves>
    __device__ __forceinline__ void issue_krgt_to_lds(
        int tid, int64_t workspace_chunk_index, const u16 *ws_krgt, u16 *s_krgt_dst)
    {
#if defined(__gfx936__) || defined(__gfx938__) || defined(__gfx946__)
        constexpr int kCopies = (8 * kTile * kTile) / 8;      // 256 x 16 B = 4 KiB（kr 段）
        constexpr int kGtBytes = kKeyDim * 4;                 // 512 B（gt 段）
        constexpr int kGtBytesPerWave = kGtBytes / Waves;     // Waves=4 => 128 B
        constexpr int kGtLanesPerWave = kGtBytesPerWave / 16; // 8 lane
        const int wave = tid >> 6;
        const int lane = tid & 63;
        const vec4_u32 rsrc = kda_c16_make_buffer_rsrc(ws_krgt);
        const unsigned int soff_bytes =
            static_cast<unsigned int>(workspace_chunk_index * (kKrgtStrideU16 * 2));
        // kr 段（区内偏移 0）
#pragma unroll
        for (int i = tid; i < kCopies; i += Waves * 64)
        {
            const int it = i / (Waves * 64);
            const unsigned int lds_slice = static_cast<unsigned int>((wave + it * Waves) * 1024);
            const int voff_bytes = i * 16;
            kda_c16_asm::buffer_load_dwordx4_lds(s_krgt_dst, rsrc, lds_slice, soff_bytes,
                                                 voff_bytes);
        }
        // gt 段（区内偏移 kDecayOffsetU16 * 2 = 4096 B）
        if (lane < kGtLanesPerWave)
        {
            const int voff_bytes = kDecayOffsetU16 * 2 + wave * kGtBytesPerWave + lane * 16;
            kda_c16_asm::buffer_load_dwordx4_lds(
                s_krgt_dst, rsrc,
                static_cast<unsigned int>(kDecayOffsetU16 * 2 + wave * kGtBytesPerWave),
                soff_bytes, voff_bytes);
        }
#else
        (void)tid;
        (void)workspace_chunk_index;
        (void)ws_krgt;
        (void)s_krgt_dst;
#endif
    }

} // namespace

#endif // FLASH_KDA_K2_LOAD_CUH
