# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Small public-entry tests; CPU input/reference, one kernel call per case.

In an installed AITER environment (configure HIP/PMD externally):
    python op_tests/gfx946_tests/silu_and_mul/test_silu_and_mul.py --suite full
    python op_tests/gfx946_tests/silu_and_mul/test_silu_and_mul.py --suite multi
    python op_tests/gfx946_tests/silu_and_mul/test_silu_and_mul.py --suite route --dtypes bf16
    python op_tests/gfx946_tests/silu_and_mul/test_silu_and_mul.py --suite invalid
    python op_tests/gfx946_tests/silu_and_mul/test_silu_and_mul.py --suite single-reject

Default quick suite is six numerical cases. --json is optional. multi/route
require a multi-XCD gfx946 runtime; single-reject checks explicit rejection on
a single-XCD runtime. Route numerical PASS needs separate TG trace evidence.
Graph is opt-in, with an external timeout on PMD (no eager result implies Graph
support): --suite graph --dtypes bf16. It changes input twice across replays.
No old results, source generators or temporary scripts are required.
"""
import argparse
from contextlib import contextmanager
import faulthandler
import hashlib
import json
import os
from pathlib import Path

import torch
import torch.nn.functional as F

DTYPES = {'bf16': torch.bfloat16, 'fp16': torch.float16}
ENV_KEYS = ('AITER_SILU_DIE_MODE', 'AITER_SILU_DIE_CHUNK', 'AITER_SILU_DIE_MASK')


@contextmanager
def launch_config(mode='auto', chunk=1, mask=0):
    previous = {key: os.environ.get(key) for key in ENV_KEYS}
    for key, value in zip(ENV_KEYS, (mode, chunk, mask)):
        os.environ[key] = str(value)
    try:
        yield
    finally:
        for key, value in previous.items():
            if value is None:
                os.environ.pop(key, None)
            else:
                os.environ[key] = value


def cpu_input(shape, dtype):
    count = 1
    for size in shape:
        count *= size
    values = torch.randn(count, generator=torch.Generator().manual_seed(946 + count)) * 4
    special = torch.tensor([-80., -20., -7., -0.5, 0., 0.5, 7., 20., 80.])
    values[:min(count, len(special))] = special[:min(count, len(special))]
    return values.reshape(shape).to(dtype)


def reference(x, limit):
    left, right = x.float().chunk(2, dim=-1)
    if limit > 0:
        left = left.clamp(max=limit).to(x.dtype).float()
        right = right.clamp(-limit, limit)
    return (F.silu(left) * right).to(x.dtype).float()


def compare(actual, expected, name):
    result = actual.cpu().float()
    tolerance = 0.01 if name == 'bf16' else 0.001
    diff = (result - expected).abs()
    bad = ~(diff <= 0.0001 + tolerance * expected.abs())
    if not bool(torch.isfinite(result).all()) or bool(bad.any()):
        raise AssertionError(f'mismatch={int(bad.sum())}, max_abs={float(diff.max())}')
    return dict(max_abs_error=float(diff.max()) if diff.numel() else 0., mismatch=0)


def eager(op, name, *, tag, shape, limit=0., call='positional', offset=0,
          mode='auto', chunk=1, mask=0, stream=False):
    dtype = DTYPES[name]
    cpu = cpu_input(shape, dtype)
    out_shape = (*shape[:-1], shape[-1] // 2)
    count = cpu.numel() // 2
    # Sentinel guards are on both sides. Offset=1 checks vector alignment fallback.
    pad = 16 + offset
    input_host = torch.full((pad + cpu.numel() + 16,), 111., dtype=dtype)
    input_host[pad:pad+cpu.numel()] = cpu.flatten()
    input_storage = input_host.cuda()
    x = input_storage[pad:pad+cpu.numel()].view(shape)
    output_host = torch.full((pad + count + 16,), 113., dtype=dtype)
    output_host[pad:pad+count] = float('nan')
    output_storage = output_host.cuda()
    out = output_storage[pad:pad+count].view(out_shape)
    work_stream = torch.cuda.Stream() if stream else torch.cuda.current_stream()
    if stream:
        work_stream.wait_stream(torch.cuda.current_stream())
    with launch_config(mode, chunk, mask), torch.cuda.stream(work_stream):
        if call == 'legacy':
            op(out, x)
        elif call == 'keyword':
            op(out, x, limit=limit)
        else:
            op(out, x, limit)
    work_stream.synchronize()
    measured = compare(out, reference(cpu, limit), name)
    assert torch.equal(input_storage.cpu(), input_host), 'input/guard modified'
    stored = output_storage.cpu()
    assert torch.equal(stored[:pad], output_host[:pad]), 'prefix overwritten'
    assert torch.equal(stored[pad+count:], output_host[pad+count:]), 'suffix overwritten'
    return dict(tag=tag, dtype=name, shape=shape, limit=limit, call=call, offset=offset,
                mode=mode, chunk=chunk, stream=stream, **measured, status='PASS')


def rejects(op, single=False):
    host = torch.zeros(3, 256, dtype=torch.float16)
    x = host.cuda()
    out = torch.empty(3, 128, dtype=torch.float16, device='cuda')
    cases = [('single_xcd_linear', lambda: op(out, x), ('linear', 1, 0), 'at least 2')]
    if not single:
        strided = host.t().contiguous().cuda().t()
        fp32 = host.float().cuda()
        output_bf16 = torch.empty(3,128,dtype=torch.bfloat16,device='cuda')
        output_fp32 = torch.empty(3,128,dtype=torch.float32,device='cuda')
        cases = [
            ('bad_mode', lambda: op(out, x), ('bad', 1, 0), 'must be auto'),
            ('chunk_zero', lambda: op(out, x), ('linear', 0, 0), 'must be positive'),
            ('chunk_negative', lambda: op(out, x), ('linear', -1, 0), 'invalid unsigned'),
            ('chunk_text', lambda: op(out, x), ('linear', 'junk', 0), 'invalid unsigned'),
            ('chunk_overflow', lambda: op(out, x), ('linear', 4294967296, 0), 'invalid unsigned'),
            ('unsupported_mask', lambda: op(out, x), ('linear', 1, 1), 'only 0'),
            ('negative_limit', lambda: op(out, x, -1.), ('auto', 1, 0), 'limit'),
            ('nan_limit', lambda: op(out, x, float('nan')), ('auto', 1, 0), 'limit'),
            ('inf_limit', lambda: op(out, x, float('inf')), ('auto', 1, 0), 'limit'),
            ('odd_width', lambda: op(out, x[:, :-1]), ('auto', 1, 0), 'even last'),
            ('wrong_shape', lambda: op(out[:, :-1], x), ('auto', 1, 0), 'shape'),
            ('noncontiguous', lambda: op(out, strided), ('auto', 1, 0), 'contiguous'),
            ('output_dtype', lambda: op(output_bf16, x), ('auto', 1, 0), 'dtype'),
            ('input_dtype', lambda: op(output_fp32, fp32), ('auto', 1, 0), 'FP16'),
            ('cpu_input', lambda: op(out, host), ('auto', 1, 0), 'same GPU'),
            ('overlap', lambda: op(x.view(-1)[:384].view(3, 128), x), ('auto', 1, 0), 'memory'),
        ]
    results = []
    for tag, call, config, message in cases:
        with launch_config(*config):
            try:
                call()
            except (RuntimeError, ValueError) as error:
                assert message in str(error), (tag, str(error))
                results.append(dict(tag=tag, status='PASS', rejection=str(error)))
            else:
                raise AssertionError(f'{tag}: expected rejection')
    return results


def graph(op, name):
    cpu = cpu_input((3, 256), DTYPES[name])
    x = cpu.cuda()
    out = torch.empty(3, 128, dtype=x.dtype, device='cuda')
    stream = torch.cuda.Stream()
    stream.wait_stream(torch.cuda.current_stream())
    # Resolve lazy module load before capture.
    with torch.cuda.stream(stream), launch_config('off'):
        op(out, x)
    stream.synchronize()
    captured = torch.cuda.CUDAGraph()
    with launch_config('linear', 2), torch.cuda.graph(captured, stream=stream):
        op(out, x)
    measured = []
    with launch_config('off'):
        for shift in (0.25, -0.5):
            changed = (cpu.float() + shift).to(cpu.dtype)
            x.copy_(changed)
            captured.replay()
            torch.cuda.synchronize()
            measured.append(compare(out, reference(changed, 0.), name))
    return dict(tag='graph_changed_input', dtype=name, replays=measured, status='PASS')


def main():
    faulthandler.enable()
    faulthandler.dump_traceback_later(90, repeat=True)
    parser = argparse.ArgumentParser(description=__doc__)
    parser.add_argument('--suite', choices=['quick', 'full', 'multi', 'route', 'invalid', 'single-reject', 'graph'], default='quick')
    parser.add_argument('--dtypes', nargs='+', choices=DTYPES, default=list(DTYPES))
    parser.add_argument('--require-arch', default='gfx946')
    parser.add_argument('--wide-rows', type=int, choices=[1, 3], default=1,
                        help='rows for K>=8192; keep 1 to limit PMD host transfers')
    parser.add_argument('--json', type=Path)
    args = parser.parse_args()
    props = torch.cuda.get_device_properties(0)
    arch = props.gcnArchName.split(':')[0]
    assert arch == args.require_arch, (arch, args.require_arch)
    # PMD initialized above. Operator selection must not depend on this variable.
    os.environ.pop('GPU_CHIP', None)
    from aiter import silu_and_mul
    result = dict(suite=args.suite, arch=arch, properties=str(props),
                  gpu_chip_present='GPU_CHIP' in os.environ, cases=[])
    try:
        for name in args.dtypes:
            if args.suite in ('invalid', 'single-reject'):
                break
            if args.suite == 'graph':
                result['cases'].append(graph(silu_and_mul, name))
                continue
            if args.suite in ('multi', 'route'):
                cases = [dict(tag='linear_chunk1',shape=(5,256),mode='linear'),
                         dict(tag='linear_chunk2',shape=(5,256),mode='linear',chunk=2),
                         dict(tag='auto_multi',shape=(5,256))]
                if args.suite == 'multi':
                    cases += [dict(tag='one_group',shape=(1,256)),
                              dict(tag='off',shape=(3,260),mode='off',chunk='ignored',mask='ignored'),
                              dict(tag='limited_tail',shape=(3,1026),mode='linear',limit=1.3),
                              dict(tag='stream',shape=(3,512),mode='linear',stream=True)]
            else:
                widths = [1, 128, 513] if args.suite == 'quick' else [1,63,64,65,128,130,192,196,256,260,384,392,512,513,4096,4104,8192,8200]
                cases = [dict(tag=f'k{k}',shape=(1 if k == 1 else args.wide_rows if k >= 8192 else 3,2*k),
                              call='legacy' if k == 1 else 'positional') for k in widths]
                if args.suite == 'full':
                    cases += [dict(tag='limit_keyword',shape=(3,256),limit=1.3,call='keyword'),
                              dict(tag='limit_positional',shape=(3,384),limit=7.),
                              dict(tag='unaligned',shape=(3,512),offset=1),
                              dict(tag='rank1',shape=(256,)),
                              dict(tag='rank3',shape=(2,3,256)),
                              dict(tag='empty_m',shape=(0,256)),
                              dict(tag='empty_k',shape=(3,0))]
            for case in cases:
                record = eager(silu_and_mul, name, **case)
                result['cases'].append(record)
                print('PASS', json.dumps(record), flush=True)
        if args.suite in ('invalid', 'single-reject'):
            result['cases'] = rejects(silu_and_mul, single=args.suite == 'single-reject')
        from aiter.jit.core import get_module
        so = Path(get_module('module_activation').__file__).resolve()
        result.update(module=str(so),sha256=hashlib.sha256(so.read_bytes()).hexdigest(),status='PASS')
    except Exception as error:
        result.update(status='FAIL',error=repr(error))
        raise
    finally:
        if args.json:
            args.json.parent.mkdir(parents=True,exist_ok=True)
            args.json.write_text(json.dumps(result,indent=2)+'\n')
        print(f"RESULT {result.get('status')} {len(result['cases'])} cases",flush=True)


if __name__ == '__main__':
    main()
