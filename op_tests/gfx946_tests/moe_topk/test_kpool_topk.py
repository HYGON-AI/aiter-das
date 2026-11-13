# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""kpool_topk 的小规模 CPU 参考验证：优化/回退、页表、offset、尾 token 和补行。

使用前：在指定容器中按同目录 README.md 配置 Torch/HIP、PMD 库路径和 clang18。
从仓库根目录设置测试脚本绝对路径，再在各自独立的结果目录执行下面的命令，
避免不同进程覆盖 m5out；GPU_CHIP 必须在 Python 启动前设置。
  test_py="$PWD/op_tests/gfx946_tests/moe_topk/test_kpool_topk.py"

已安装 wheel，或只复制本目录测试文件时，直接运行下面的数值命令；不要加 --rebuild。
--package-mode installed 使用当前 Python 环境的 AITER，build 集合仅验证模块加载。
在完整源码 checkout 中首次运行或源码变更后，重编译并加载对应模块：
  GPU_CHIP=sb python "$test_py" --package-mode source --suite build --rebuild --json build.json
单 die（1 XCD），运行全部数值用例和启动配置检查：
  GPU_CHIP=sb python "$test_py" --suite all --expect-xcds 1 --json single.json
多 die（一张 GPU、2 XCD），复用上一步构建的模块：
  GPU_CHIP=sbx2 python "$test_py" --suite all --expect-xcds 2 --json dual.json
显式多 die 分发，使用多个 workgroup 检查 chunk=2：
  GPU_CHIP=sbx2 python "$test_py" --suite route --expect-xcds 2 --die-mode linear --chunk 2 --json linear2.json

默认 quick 只跑少量用例；full 只做数值，all 额外做配置拒绝检查。
all 共6个数值用例；route 覆盖 pool16、pool4 和通用回退。
--list 列出用例且不初始化 GPU；--case pool16 可只运行一个用例。
每例仅调用一次算子，无预热/计时；JSON 保存逐例结果、拓扑及源码/模块哈希。
--expect-xcds 核验实际拓扑；数值 PASS 之外还须用 completedWGs 确认跨 XCD 执行。
--die-mode off 仅表示普通启动 API，不等同单 die；本测试不验收 Graph 或性能。
"""
import os
import _index_topk_common as common

PREFIX = "SGL_KERNEL_KPOOL_TOPK"
CASES = [
    dict(name="pool16", op="kpool_topk", pool=16, group_k=128, rows=5, quick=True, route=True, config=True),
    dict(name="pool4", op="kpool_topk", pool=4, group_k=512, rows=5, route=True),
    dict(name="generic", op="kpool_topk", pool=8, group_k=64, rows=5, route=True),
    dict(name="forced_fallback", op="kpool_topk", pool=16, group_k=128, rows=3, fallback=True),
    dict(name="page_lookup", op="kpool_topk", pool=16, group_k=128, rows=3, page=True, mixed=True),
    dict(name="sorted_offset", op="kpool_topk", pool=16, group_k=128, rows=3, sorted=True, mixed=True),
]
for _case in CASES:
    _case["prefix"] = PREFIX


def prepare(case):
    torch, aiter = common.torch, common.aiter
    pool, k, rows = case["pool"], case["group_k"], case["rows"]
    cols = k + 17
    score = common.scores(rows, cols)
    starts = torch.tensor([i % 4 for i in range(rows)], dtype=torch.int32)
    lengths = torch.tensor([k + 7] * rows, dtype=torch.int32)
    if case.get("mixed"):
        lengths[:2] = torch.tensor([0, 7], dtype=torch.int32)
    tails = torch.tensor([i % (pool - 1) + 1 for i in range(rows)], dtype=torch.int32)
    seq_lens = lengths * pool + tails
    offsets = torch.arange(rows, dtype=torch.int32) * 4096
    out_rows = rows + (2 if case.get("mixed") else 0)
    width = pool * k + pool - 1
    page_rows = torch.arange(rows, dtype=torch.int32) % 2
    table = torch.arange((cols + 1) * pool, dtype=torch.int32).repeat(2, 1) * 3
    table[1] += 100000
    expected = torch.full((out_rows, width), -1, dtype=torch.int32)
    for row in range(rows):
        start, length = int(starts[row]), int(lengths[row])
        group_ids = score[row, start:start + length].topk(min(length, k)).indices
        raw = (group_ids[:, None] * pool + torch.arange(pool)).flatten().int()
        raw = torch.cat((raw, length * pool + torch.arange(int(tails[row]), dtype=torch.int32)))
        mapped = table[page_rows[row], raw.long()] if case.get("page") else raw + offsets[row]
        expected[row, :raw.numel()] = mapped
    params = dict(row_starts=starts.cuda(), seq_lens=seq_lens.cuda(), out_rows=out_rows)
    if case.get("page"):
        params.update(page_table=table.cuda(), page_table_row_index=page_rows.cuda())
    else:
        params["topk_indices_offset"] = offsets.cuda()
    x, lens = score.cuda(), lengths.cuda()
    holder = {}

    def call():
        os.environ[PREFIX + "_FORCE_FALLBACK"] = "1" if case.get("fallback") else "0"
        os.environ[PREFIX + "_SORT_WRITEBACK"] = "1" if case.get("sorted") else "0"
        holder["out"] = aiter.kpool_topk(x, lens, pool, pool * k, **params)

    def check():
        got = holder["out"].cpu()
        assert got.shape == expected.shape
        assert torch.equal(got.sort(-1).values, expected.sort(-1).values), "pool token set differs from reference"
        assert torch.equal(x.cpu(), score), "input changed"
        return dict(output_sha256=common.digest(got.sort(-1).values), rows=out_rows)

    return call, check, dict(input_sha256=common.digest(score))


if __name__ == "__main__":
    common.main("module_kpool_topk", CASES, prepare, [PREFIX],
                ["csrc/kernels/kpool_topk.cu", "csrc/kernels/kpool_topk_fallback.cu",
                 "csrc/pybind/kpool_topk_pybind.cu", "aiter/ops/kpool_topk.py"], __file__)
