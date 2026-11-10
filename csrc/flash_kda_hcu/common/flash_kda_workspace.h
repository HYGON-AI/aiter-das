// SPDX-License-Identifier: MIT
// Copyright (c) 2026 Hygon Information Technology Co., Ltd.
#pragma once

// FlashKDA workspace 布局与路由：纯 host、无 torch 依赖，供 native forward 与
// 冷路径 spec 共用（唯一事实来源）。

#include <cctype>
#include <cstddef>
#include <cstdint>
#include <cstdlib>
#include <stdexcept>
#include <string>

namespace flash_kda
{

    enum class KdaPath
    {
        Fixed,
        Segmented,
        Varlen,
    };

    struct Region
    {
        size_t offset = 0;
        size_t bytes = 0;
    };

    struct WorkspaceLayout
    {
        KdaPath path = KdaPath::Fixed;
        bool is_varlen = false;
        int64_t batch = 0;
        int64_t tokens = 0;
        int64_t heads = 0;
        int64_t sequence_count = 0;
        int64_t head_stride_chunks = 0;
        int64_t workspace_chunks = 0;   // P = heads * head_stride_chunks
        int64_t chunks_per_segment = 0; // 0 表示不分段
        int64_t segment_count = 0;
        Region kdqd;
        Region krgt;
        Region inv;
        Region mqk;
        Region beta_sigmoid;
        Region chunk_info;
        Region sequence_info;
        Region segment_transition;
        Region segment_update;
        Region segment_initial_states;
        size_t numeric_bytes = 0;
        size_t total_bytes = 0;
    };

    // ---- 固定几何 ----
    constexpr int64_t kChunkSize = 16;
    constexpr int64_t kKeyDim = 128;
    constexpr int64_t kValueDim = 128;

    // 每 chunk 数值区字节数：kdqd 8 KiB + krgt 4608 B + inv 512 + mqk 512 + beta 64
    constexpr size_t kKdqdBytesPerChunk = 8192;
    constexpr size_t kKrgtBytesPerChunk = 4608;
    constexpr size_t kInvBytesPerChunk = 512;
    constexpr size_t kMqkBytesPerChunk = 512;
    constexpr size_t kBetaSigmoidBytesPerChunk = 64;
    constexpr size_t kNumericBytesPerChunk = kKdqdBytesPerChunk + kKrgtBytesPerChunk +
                                             kInvBytesPerChunk + kMqkBytesPerChunk +
                                             kBetaSigmoidBytesPerChunk; // 13888

    // packed metadata
    constexpr size_t kChunkInfoBytesPerChunk = 16;  // INT64[Qcap, 2]
    constexpr size_t kSequenceInfoBytesPerSeq = 24; // INT64[N, 3]

    // 分段附加区（每个 (segment, B, H)）
    constexpr size_t kSegmentTransitionBytes = 32768;    // BF16
    constexpr size_t kSegmentUpdateBytes = 65536;        // FP32
    constexpr size_t kSegmentInitialBytes = 65536;       // FP32

    // ---- 路由常量（与生产路由一致）----
    constexpr int64_t kPlainCtaPerBh = 2;   // plain K2 的 grid = (2, B*H)
    constexpr int64_t kCuCount = 80;        // 单卡 CU 数
    constexpr int64_t kMaxPlainCtas = 32;   // 0.40 * 80
    constexpr int64_t kMinSegmentTokens = 4096;
    constexpr int64_t kShortTokens = 8192;
    constexpr int64_t kCpsShort = 32;
    constexpr int64_t kTargetSegments = 16;
    constexpr int64_t kCpsMin = 32;
    constexpr int64_t kCpsMax = 128;
    constexpr size_t kAlignBytes = 16;

    // launcher / 指令寻址上限（与 kernel 形参和 MUBUF soffset 一致）
    constexpr int64_t kMaxGridY = 65535;                                   // grid.y 上限
    constexpr int64_t kMaxInt = 2147483647;                                // int 形参上限
    constexpr int64_t kMubufLimit = int64_t(1) << 31;                      // MUBUF 32 位偏移

    namespace detail
    {

        inline int64_t checked_mul(int64_t a, int64_t b, const char *what)
        {
            if (a < 0 || b < 0)
            {
                throw std::invalid_argument(std::string("negative operand: ") + what);
            }
            if (a != 0 && b > INT64_MAX / a)
            {
                throw std::overflow_error(std::string("size overflow: ") + what);
            }
            return a * b;
        }

        inline int64_t checked_add(int64_t a, int64_t b, const char *what)
        {
            if (a < 0 || b < 0)
            {
                throw std::invalid_argument(std::string("negative operand: ") + what);
            }
            if (b > INT64_MAX - a)
            {
                throw std::overflow_error(std::string("size overflow: ") + what);
            }
            return a + b;
        }

        inline size_t align_up(size_t value, size_t align)
        {
            if (value > SIZE_MAX - align)
            {
                throw std::overflow_error("align_up overflow");
            }
            return (value + align - 1) / align * align;
        }

        // ceil(value/divisor)，带溢出检查（`tokens+15` 这类表达式不能裸写）。
        inline int64_t ceil_div(int64_t value, int64_t divisor, const char *what)
        {
            return checked_add(value, divisor - 1, what) / divisor;
        }

        inline void reserve(WorkspaceLayout &layout, Region &region, size_t bytes, size_t &cursor)
        {
            if (bytes == 0)
            {
                region = Region{};
                return;
            }
            cursor = align_up(cursor, kAlignBytes);
            region.offset = cursor;
            region.bytes = bytes;
            cursor = static_cast<size_t>(detail::checked_add(static_cast<int64_t>(cursor), static_cast<int64_t>(bytes), "cursor"));
        }

        inline std::string trim_lower(const char *raw)
        {
            std::string value = raw == nullptr ? std::string() : std::string(raw);
            size_t begin = 0;
            while (begin < value.size() &&
                   std::isspace(static_cast<unsigned char>(value[begin])))
            {
                ++begin;
            }
            size_t end = value.size();
            while (end > begin && std::isspace(static_cast<unsigned char>(value[end - 1])))
            {
                --end;
            }
            std::string out = value.substr(begin, end - begin);
            for (char &ch : out)
            {
                ch = static_cast<char>(std::tolower(static_cast<unsigned char>(ch)));
            }
            return out;
        }

    // launcher 与指令寻址上限；spec 与 forward 共用（不允许绕过）。
    inline void validate_launch_limits(const WorkspaceLayout &layout)
    {
        if (layout.tokens > kMaxInt)
        {
            throw std::invalid_argument("T/T_total exceeds INT_MAX");
        }
        const int64_t grid_y = layout.is_varlen ? layout.sequence_count * layout.heads
                                                : layout.batch * layout.heads;
        if (grid_y < 1 || grid_y > kMaxGridY)
        {
            throw std::invalid_argument("grid.y (B*H or N*H) must be in [1, 65535]");
        }
        if (layout.head_stride_chunks > kMaxInt / kChunkSize)
        {
            throw std::invalid_argument("Qcap exceeds INT_MAX/16");
        }
        if (layout.head_stride_chunks * static_cast<int64_t>(kKdqdBytesPerChunk) >= kMubufLimit)
        {
            throw std::invalid_argument("Qcap*8192 must be < 2^31 (MUBUF soffset)");
        }
        if (layout.total_bytes > static_cast<size_t>(INT64_MAX))
        {
            throw std::overflow_error("workspace total bytes exceed INT64_MAX");
        }
    }

    } // namespace detail

    // `FLASH_KDA_HCU_SEGMENT`：auto/空 走自动路由；0/off/false/none 强制 plain；
    // 其他值报错（与公开 API 的既有语义一致）。
    inline bool force_plain_from_env()
    {
        const std::string value = detail::trim_lower(std::getenv("FLASH_KDA_HCU_SEGMENT"));
        if (value.empty() || value == "auto")
        {
            return false;
        }
        if (value == "0" || value == "off" || value == "false" || value == "none")
        {
            return true;
        }
        throw std::invalid_argument(
            "FLASH_KDA_HCU_SEGMENT accepts only 'auto' or 0/off/false/none, got: " + value);
    }

    // 定长分段粒度：返回 0 表示不分段。
    inline int64_t segment_chunks_for(int64_t batch, int64_t tokens, int64_t heads)
    {
        if (detail::checked_mul(kPlainCtaPerBh, detail::checked_mul(batch, heads, "B*H"), "2*B*H") >=
            kMaxPlainCtas)
        {
            return 0;
        }
        if (tokens < kMinSegmentTokens)
        {
            return 0;
        }
        if (tokens <= kShortTokens)
        {
            return kCpsShort;
        }
        const int64_t chunks = (tokens + kChunkSize - 1) / kChunkSize;
        const int64_t cps = (chunks + kTargetSegments - 1) / kTargetSegments;
        return cps < kCpsMin ? kCpsMin : (cps > kCpsMax ? kCpsMax : cps);
    }

    inline WorkspaceLayout make_workspace_layout(int64_t batch, int64_t tokens, int64_t heads,
                                                 int64_t sequence_count, bool is_varlen,
                                                 bool force_plain)
    {
        if (batch < 1 || heads < 1)
        {
            throw std::invalid_argument("batch and heads must be positive");
        }
        if (tokens < 0)
        {
            throw std::invalid_argument("tokens must be non-negative");
        }
        if (is_varlen && batch != 1)
        {
            throw std::invalid_argument("packed varlen requires physical batch == 1");
        }
        if (is_varlen && sequence_count < 1)
        {
            throw std::invalid_argument("packed varlen requires sequence_count >= 1");
        }

        WorkspaceLayout layout;
        layout.batch = batch;
        layout.tokens = tokens;
        layout.heads = heads;
        layout.sequence_count = is_varlen ? sequence_count : batch;

        int64_t head_stride_chunks = 0;
        int64_t cps = 0;
        if (is_varlen)
        {
            layout.path = KdaPath::Varlen;
            const int64_t chunks = detail::ceil_div(tokens, kChunkSize, "ceil(T/16)");
            head_stride_chunks = detail::checked_add(chunks, layout.sequence_count,
                                                     "Qcap = ceil(T/16) + N");
        }
        else
        {
            const int64_t chunks = detail::ceil_div(tokens, kChunkSize, "ceil(T/16)");
            head_stride_chunks = detail::checked_mul(batch, chunks, "B*chunks");
            cps = force_plain ? 0 : segment_chunks_for(batch, tokens, heads);
            layout.path = cps > 0 ? KdaPath::Segmented : KdaPath::Fixed;
        }

        layout.is_varlen = is_varlen;
        layout.head_stride_chunks = head_stride_chunks;
        layout.workspace_chunks = detail::checked_mul(heads, head_stride_chunks,
                                                      "P = H*head_stride_chunks");
        layout.chunks_per_segment = cps;
        layout.segment_count =
            cps > 0 ? (head_stride_chunks / batch + cps - 1) / cps : 0;

        const int64_t p = layout.workspace_chunks;
        size_t cursor = 0;
        detail::reserve(layout, layout.kdqd,
                        static_cast<size_t>(detail::checked_mul(p, kKdqdBytesPerChunk, "kdqd")),
                        cursor);
        detail::reserve(layout, layout.krgt,
                        static_cast<size_t>(detail::checked_mul(p, kKrgtBytesPerChunk, "krgt")),
                        cursor);
        detail::reserve(layout, layout.inv,
                        static_cast<size_t>(detail::checked_mul(p, kInvBytesPerChunk, "inv")),
                        cursor);
        detail::reserve(layout, layout.mqk,
                        static_cast<size_t>(detail::checked_mul(p, kMqkBytesPerChunk, "mqk")),
                        cursor);
        detail::reserve(layout, layout.beta_sigmoid,
                        static_cast<size_t>(detail::checked_mul(p, kBetaSigmoidBytesPerChunk,
                                                               "beta_sigmoid")),
                        cursor);
        layout.numeric_bytes = cursor;

        if (is_varlen)
        {
            detail::reserve(layout, layout.chunk_info,
                            static_cast<size_t>(detail::checked_mul(head_stride_chunks,
                                                                    kChunkInfoBytesPerChunk,
                                                                    "chunk_info")),
                            cursor);
            detail::reserve(layout, layout.sequence_info,
                            static_cast<size_t>(detail::checked_mul(layout.sequence_count,
                                                                    kSequenceInfoBytesPerSeq,
                                                                    "sequence_info")),
                            cursor);
        }
        if (cps > 0)
        {
            const int64_t segment_bh = detail::checked_mul(layout.segment_count,
                                                           detail::checked_mul(batch, heads, "B*H"),
                                                           "S*B*H");
            detail::reserve(layout, layout.segment_transition,
                            static_cast<size_t>(detail::checked_mul(segment_bh,
                                                                    kSegmentTransitionBytes,
                                                                    "segment_transition")),
                            cursor);
            detail::reserve(layout, layout.segment_update,
                            static_cast<size_t>(detail::checked_mul(segment_bh,
                                                                    kSegmentUpdateBytes,
                                                                    "segment_update")),
                            cursor);
            detail::reserve(layout, layout.segment_initial_states,
                            static_cast<size_t>(detail::checked_mul(segment_bh,
                                                                    kSegmentInitialBytes,
                                                                    "segment_initial_states")),
                            cursor);
        }

        layout.total_bytes = detail::align_up(cursor, kAlignBytes);
        detail::validate_launch_limits(layout);
        return layout;
    }

} // namespace flash_kda
