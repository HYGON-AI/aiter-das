# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""One size per process for xprof / PMD; stdlib, torch and AITER only.

--list prints the frozen BF16 matrix without initializing a GPU. By default the
DUT runs once, bracketed by DUT_BEGIN/DUT_END; setup and CPU checks are outside
that interval. --warmup/--repeat are explicit hardware-only timing controls.
No event time is reported as PMD GPU time: use per-dispatch simulator cycles.
"""
import argparse
import hashlib
import json
import os
from pathlib import Path


def matrix():
    result = []
    sums = [(3, k, h) for k, h in
            [(1, 1), (2, 63), (3, 65), (4, 64), (5, 127), (6, 129),
             (8, 1025), (7, 17), (0, 16)]]
    sums += [(0, 2, 16), (3, 4, 0)]
    sums += [(m, 8, 4096) for m in (1, 48, 96, 192)]
    sums += [(192, k, 4096) for k in (2, 3)]
    for m, k, h in sums:
        result.append(dict(name=f'sum_m{m}_k{k}_h{h}', op='sum', m=m, k=k, h=h))
    sorts = [dict(m=5, e=8, k=2, b=4, h=16),
             dict(m=9, e=16, k=4, b=8, h=16, mask=True, invalid=True, no_buf=True),
             dict(m=1, e=1, k=1, b=1, h=16),
             dict(m=7, e=8, k=3, b=3, h=16, invalid=True),
             dict(m=0, e=8, k=2, b=4, h=16),
             dict(m=3, e=8, k=2, b=8, h=16, all_invalid=True),
             dict(m=3, e=8, k=2, b=8, h=16, all_masked=True),
             dict(m=257, e=64, k=2, b=8, h=16, mask=True, invalid=True),
             dict(m=1025, e=16, k=2, b=32, h=16, no_buf=True)]
    sorts += [dict(m=m, e=64, k=8, b=32, h=4096) for m in (32, 256, 1024)]
    for i, c in enumerate(sorts):
        result.append(dict(name=f'sort{i:02d}_m{c["m"]}_e{c["e"]}_k{c["k"]}_h{c["h"]}',
                           op='sorting', **c))
    return result


def prepare_sum(c, dtype, torch, aiter):
    m, k, h = (c[x] for x in ('m', 'k', 'h'))
    cpu = torch.randn((m, k, h), generator=torch.Generator().manual_seed(946)).to(dtype)
    if k in (2, 4, 5, 6, 8):
        ref = torch.zeros((m, h), dtype=dtype)
        for rank in range(k):
            ref = (ref.float() + cpu[:, rank, :].float()).to(dtype)
    else:
        ref = cpu.float().sum(1).to(dtype)
    inp = cpu.to('cuda')
    out = torch.full((m, h), float('nan'), dtype=dtype).to('cuda')
    def invoke():
        aiter.moe_sum(inp, out)
    def check():
        torch.testing.assert_close(out.cpu(), ref, rtol=1e-6 if dtype == torch.float32 else 0,
                                   atol=1e-6 if dtype == torch.float32 else 0)
        return dict(max_abs=float((out.cpu().float()-ref.float()).abs().max()) if m*h else 0,
                    no_kernel=not bool(m*h))
    return invoke, check


def prepare_sort(c, dtype, torch, aiter):
    m, e, k, b, h = (c[x] for x in ('m', 'e', 'k', 'b', 'h'))
    ids = (torch.arange(m)[:, None]*3 + torch.arange(k)[None, :]).remainder(e).int()
    if c.get('invalid') and m:
        ids[0, 0] = -1
        if m > 1:
            ids[1, 0] = e
    if c.get('all_invalid'):
        ids.fill_(-1)
    weights = (torch.arange(m*k).reshape(m, k).float()+1)/32
    mask = (torch.arange(e).remainder(3) != 1).int() if c.get('mask') else None
    if c.get('all_masked'):
        mask = torch.zeros(e, dtype=torch.int32)
    cap = max(0, m*k+e*b-k)
    si = torch.empty(cap, dtype=torch.int32, device='cuda')
    sw = torch.empty(cap, dtype=torch.float32, device='cuda')
    se = torch.empty((cap+b-1)//b, dtype=torch.int32, device='cuda')
    positions = torch.empty(2*e, dtype=torch.int32, device='cuda')
    valid = torch.empty(1, dtype=torch.int32, device='cuda')
    buf = None if c.get('no_buf') else torch.full((m, h), 7., dtype=dtype).to('cuda')
    i, w = ids.to('cuda'), weights.to('cuda')
    em = None if mask is None else mask.to('cuda')
    def invoke():
        aiter.moe_sorting_fwd(i, w, si, sw, se, positions, valid, buf, e, b, em)
    def check():
        got_i, got_w = si.cpu().tolist(), sw.cpu().tolist()
        expected_e, counts, offsets = [], [], []
        offset = local = 0
        for expert in range(e):
            offsets.append(offset)
            routes = (ids == expert).nonzero().tolist() if mask is None or mask[expert] else []
            counts.append(len(routes))
            span = (len(routes)+b-1)//b*b
            expected = [(t | (rank << 24), weights[t, rank].item()) for t, rank in routes]
            expected += [(m | (k << 24), 0.)]*(span-len(routes))
            assert sorted(zip(got_i[offset:offset+span], got_w[offset:offset+span])) == sorted(expected)
            expected_e += [expert if mask is None else local]*(span//b)
            offset += span
            if mask is not None and mask[expert]:
                local += 1
        assert valid.cpu().item() == offset
        assert positions.cpu().tolist() == counts+offsets
        assert se.cpu()[:len(expected_e)].tolist() == expected_e
        if buf is not None:
            assert torch.count_nonzero(buf.cpu()) == 0
        return dict(padded=offset)
    return invoke, check


def main():
    p = argparse.ArgumentParser(description=__doc__)
    p.add_argument('--list', action='store_true')
    p.add_argument('--case')
    p.add_argument('--dtype', choices=('bf16', 'fp16', 'fp32'), default='bf16')
    p.add_argument('--require-arch', choices=('gfx936', 'gfx938', 'gfx946'))
    p.add_argument('--die-mode', choices=('auto', 'off', 'linear'), default='auto')
    p.add_argument('--warmup', type=int, default=0)
    p.add_argument('--repeat', type=int, default=1)
    p.add_argument('--json', type=Path)
    args = p.parse_args()
    if args.list:
        print(json.dumps(matrix(), indent=2)); return
    assert args.warmup >= 0 and args.repeat >= 1
    c = next(c for c in matrix() if c['name'] == args.case)
    import torch
    import aiter
    torch.cuda.init()
    prop = torch.cuda.get_device_properties(0)
    arch = prop.gcnArchName.split(':')[0]
    if args.require_arch:
        assert arch == args.require_arch, prop
    if arch == 'gfx946':
        assert args.warmup == 0 and args.repeat == 1, 'PMD runs each size once'
    os.environ.pop('GPU_CHIP', None)
    for prefix in ('AITER_MOE_SUM', 'AITER_MOE_SORTING'):
        os.environ[prefix+'_DIE_MODE'] = args.die_mode
        os.environ[prefix+'_DIE_CHUNK'] = '1'
        os.environ[prefix+'_LOG_LAUNCH'] = '1'
    dtype = dict(bf16=torch.bfloat16, fp16=torch.float16, fp32=torch.float32)[args.dtype]
    invoke, check = (prepare_sum if c['op'] == 'sum' else prepare_sort)(c, dtype, torch, aiter)
    from aiter.jit.core import get_module
    name = 'module_moe_utils' if c['op'] == 'sum' else 'module_cpp_api'
    binary = Path(get_module(name).__file__)
    info = dict(case=c, dtype=args.dtype, arch=prop.gcnArchName,
                device=str(prop), cu=prop.multi_processor_count, torch=torch.__version__,
                hip=torch.version.hip, aiter=aiter.__file__, binary=str(binary),
                binary_sha256=hashlib.sha256(binary.read_bytes()).hexdigest(),
                test_sha256=hashlib.sha256(Path(__file__).read_bytes()).hexdigest(),
                warmup=args.warmup, repeat=args.repeat, die_mode=args.die_mode)
    print('ENV', json.dumps(info), flush=True)
    for _ in range(args.warmup):
        invoke()
    torch.cuda.synchronize()
    print('DUT_BEGIN', c['name'], flush=True)
    for _ in range(args.repeat):
        invoke()
    torch.cuda.synchronize()
    print('DUT_END', c['name'], flush=True)
    info['correctness'] = check()
    info['passed'] = True
    if args.json:
        args.json.write_text(json.dumps(info, indent=2), encoding='utf8')
    print('PASS', json.dumps(info['correctness']), flush=True)


if __name__ == '__main__':
    main()
