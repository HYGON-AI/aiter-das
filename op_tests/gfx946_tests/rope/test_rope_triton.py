# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""框架两个 THD positions RoPE 接口的独立 Triton 验证。

环境配置与原生脚本相同，但不使用 AITER_ROPE_DIE_MODE。
  GPU_CHIP=sb python /path/to/test_rope_triton.py --expect-xcds 1 --json single.json
  GPU_CHIP=sbx2 python /path/to/test_rope_triton.py --expect-xcds 2 --json dual.json
  python /path/to/test_rope_triton.py --require-arch gfx938 --json hardware.json
--case 可单独重跑；--list 不初始化 GPU。每个目录须独立，保留编译异常和
原始 completedWGs；拓扑有两个 XCD 不等于 kernel 已在两个 XCD 上执行。
"""
import argparse
import hashlib
import json
import os
from pathlib import Path
import sys
import traceback

import test_rope as reference

CASES = [dict(name=f"{'offsets' if offsets else 'positions'}_{kind}", offsets=offsets,
              style=style, reuse=reuse, nope=nope, partial=partial, heads=heads, dtype=dtype)
         for offsets in (False, True)
         for kind, style, reuse, nope, partial, heads, dtype in
         (("equal", 1, True, False, False, 2, "float32"),
          ("grouped", 0, True, False, False, 4, "float16"),
          ("partial", 1, True, True, True, 4, "bfloat16"),
          ("expanded", 0, False, False, False, 2, "float32"))]


def main():
    ap = argparse.ArgumentParser(description=__doc__, formatter_class=argparse.RawDescriptionHelpFormatter)
    ap.add_argument("--require-arch", default="gfx946")
    ap.add_argument("--expect-xcds", type=int)
    ap.add_argument("--case", nargs="+")
    ap.add_argument("--list", action="store_true")
    ap.add_argument("--disable-buffer-ops", action="store_true",
                    help="use ordinary pointer operations for compiler compatibility")
    ap.add_argument("--json", type=Path)
    args = ap.parse_args()
    if args.list:
        print(json.dumps(CASES, indent=2))
        return
    sys.path.insert(0, str(reference.ROOT))
    if args.disable_buffer_ops:
        os.environ["AMDGCN_USE_BUFFER_OPS"] = "0"
    result = dict(status="RUNNING", numerical=[])

    def save():
        if args.json:
            args.json.parent.mkdir(parents=True, exist_ok=True)
            args.json.write_text(json.dumps(result, indent=2) + "\n", encoding="utf-8")
    try:
        import torch
        import triton
        import aiter.ops.triton.rope as rope
        reference.torch = torch
        torch.set_num_threads(1)
        torch.cuda.init()
        arch = torch.cuda.get_device_properties(0).gcnArchName.split(":")[0]
        assert arch == args.require_arch, arch
        agents = reference.topology() if arch == "gfx946" else []
        if args.expect_xcds is not None:
            assert len(agents) == 1 and agents[0]["xcd_status"] == 0 and agents[0]["xcds"] == args.expect_xcds, agents
        source = Path(rope.__file__).resolve()
        assert source == reference.ROOT / "aiter/ops/triton/rope.py", source
        result.update(arch=arch, topology=agents, torch=torch.__version__, triton=triton.__version__,
                      triton_path=triton.__file__, source=str(source),
                      source_sha256=hashlib.sha256(source.read_bytes()).hexdigest(),
                      buffer_ops=os.environ.get("AMDGCN_USE_BUFFER_OPS", "1"),
                      compiler=os.environ.get("TRITON_HIP_CLANG_PATH", "default"),
                      gpu_chip=os.environ.pop("GPU_CHIP", None))
        print("ENV", json.dumps(result), flush=True)
        save()
        if args.case:
            assert set(args.case) <= {c["name"] for c in CASES}
        for c in CASES:
            if args.case and c["name"] not in args.case:
                continue
            generator = torch.Generator().manual_seed(20261112)
            dtype = getattr(torch, c["dtype"])
            d, t = 16, 3
            f = (d // 2 if c["partial"] else d) // (2 if c["reuse"] else 1)
            angles = torch.randn((12, f), generator=generator)
            cos, sin = angles.cos(), angles.sin()
            positions = torch.tensor([5, 1, 7], dtype=torch.int64)
            offsets = torch.tensor([1, 2, -1], dtype=torch.int64)
            indices = positions + offsets if c["offsets"] else positions
            buffers, expected = [], []
            for h in (c["heads"], 2):
                x = torch.randn((t, h, d), generator=generator).to(dtype)
                buffers.append(reference.guarded(x, "contiguous"))
                expected.append(reference.rotate(x.double(), cos[indices, None].double(), sin[indices, None].double(), c["style"], c["reuse"], c["nope"]))
            api = "rope_cached_thd_positions_" + ("offsets_" if c["offsets"] else "") + "2c_fwd_inplace"
            extras = [cos, sin, positions] + ([offsets] if c["offsets"] else [])
            gpu_extras = [x.cuda() for x in extras]
            print("DUT_BEGIN", c["name"], flush=True)
            outputs = getattr(rope, api)(*[v[0] for v in buffers], *gpu_extras, c["style"], c["reuse"], c["nope"])
            torch.cuda.synchronize()
            print("DUT_END", c["name"], flush=True)
            errors = []
            for output, ref, (view, base, original, cpu_view) in zip(outputs, expected, buffers):
                assert output.data_ptr() == view.data_ptr()
                got = output.cpu()
                atol, rtol = {torch.float32: (4e-6, 3e-6), torch.float16: (0.003, 0.002), torch.bfloat16: (0.025, 0.012)}[dtype]
                torch.testing.assert_close(got.double(), ref, atol=atol, rtol=rtol)
                cpu_view.copy_(got)
                assert torch.equal(base.cpu(), original), "guard modified"
                errors.append(float((got.double() - ref).abs().max()))
            for dev, host in zip(gpu_extras, extras):
                assert torch.equal(dev.cpu(), host), "cache or indices modified"
            result["numerical"].append(c | dict(api=api, max_abs=errors))
            print("PASS", c["name"], flush=True)
            save()
        result["status"] = "PASS"
    except Exception:
        result.update(status="FAIL", error=traceback.format_exc())
        save()
        raise
    save()
    print("SUMMARY", result["status"], len(result["numerical"]), flush=True)


if __name__ == "__main__":
    main()
