# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""gfx936 regression for a gfx936/gfx938 W8A8 fat binary.

Run from the repository root with GPU_ARCHS='gfx936;gfx938'. Requires only
AITER, Torch and the adjacent permanent W8A8 test module.
"""
import argparse
import json
from pathlib import Path

import torch
import aiter
from aiter.ops.gemm_op_a8w8 import gemm_a8w8, _gemm_a8w8_blockscale
from test_w8a8_gemm import cases_for, run_case


def main():
    parser = argparse.ArgumentParser(description=__doc__)
    parser.add_argument('--json', type=Path)
    args = parser.parse_args()
    arch = torch.cuda.get_device_properties(torch.cuda.current_device()).gcnArchName.split(':')[0]
    assert arch == 'gfx936', arch
    torch.manual_seed(936)
    torch.set_num_threads(1)
    results = []
    for dtype in (torch.float16, torch.bfloat16):
        for suite in ('full', 'optimized'):
            for case in cases_for('rowwise', suite):
                result = run_case(torch, aiter, 'rowwise', torch.int8, dtype, case)
                results.append(dict(check='int8', **result))

        # Create FP8 on the CPU so the rejection test itself needs no GPU FP8
        # conversion kernel. Native entry points must also reject, before any
        # GEMM or MX scale-decode launch and without modifying the output.
        a = torch.ones((3, 128)).to(torch.float8_e4m3fn).cuda()
        b = torch.ones((32, 128)).to(torch.float8_e4m3fn).cuda()
        for op in ('rowwise', 'blockscale', 'mx'):
            if op == 'rowwise':
                sa, sb = torch.ones((3, 1), device='cuda'), torch.ones((1, 32), device='cuda')
            elif op == 'blockscale':
                sa, sb = torch.ones((3, 1), device='cuda'), torch.ones((1, 1), device='cuda')
            else:
                sa = torch.full((3, 4), 127, dtype=torch.uint8, device='cuda')
                sb = torch.full((1, 4), 127, dtype=torch.uint8, device='cuda')
            for native in (False, True):
                out = torch.full((3, 32), -23, dtype=dtype, device='cuda')
                try:
                    if op == 'rowwise':
                        if native:
                            gemm_a8w8(a, b, sa, sb, out, None, 0)
                        else:
                            aiter.gemm_a8w8_CK(a, b, sa, sb, dtype=dtype)
                    elif native:
                        _gemm_a8w8_blockscale(a, b, sa, sb, out)
                    else:
                        aiter.gemm_a8w8_blockscale(a, b, sa, sb, out)
                except RuntimeError as error:
                    message = str(error)
                    assert 'W8A8 CK FP8 requires gfx92a, gfx938 or gfx946; got gfx936' in message, message
                else:
                    raise AssertionError(f'gfx936 FP8 accepted: {op}, native={native}')
                torch.cuda.synchronize()
                assert torch.all(out == -23).item()
                results.append(dict(check='fp8_reject', op=op, native=native, dtype=str(dtype)))
    report = dict(arch=arch, torch=torch.__version__, hip=torch.version.hip,
                  aiter=aiter.__file__, cases=results, complete=True)
    if args.json:
        args.json.write_text(json.dumps(report, indent=2) + '\n')
    print(f'RESULT PASS {len(results)} cases', flush=True)


if __name__ == '__main__':
    main()
