# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""Small RMSNorm correctness tests: CPU reference, one DUT call per case.

Run in a configured HIP environment with installed AITER:
    python op_tests/gfx946_tests/rmsnorm/test_rmsnorm.py --suite quick
    python op_tests/gfx946_tests/rmsnorm/test_rmsnorm.py --suite full
    python op_tests/gfx946_tests/rmsnorm/test_rmsnorm.py --suite multi
    python op_tests/gfx946_tests/rmsnorm/test_rmsnorm.py --suite route --dtypes bf16
Use --ops to select one or more of the three public APIs (default: all).
Optional: --json result.json, --require-arch gfx946, --expect-xcds 2.
PMD model selection (sb/sbx2/sbx4) is external. No benchmarking or warmup is used.
Route PASS needs per-dispatch XCD counters in addition to numerical results.
--resume reuses only matching cases with identical test, binary and environment
identity, to avoid repeating quick tests in a CPU simulator. It is optional;
ordinary use requires no temporary helper scripts or prior results. If the JIT
module is missing it is built from the AITER/CK checkout. Use --rebuild after
native source changes to rebuild it explicitly; all five RMSNorm APIs share it.
See the sibling README.md for standalone commands and build prerequisites.
"""

import argparse
from contextlib import contextmanager
import ctypes
import ctypes.util
import hashlib
import inspect
import json
import os
from pathlib import Path

import torch


DTYPES = {'bf16': torch.bfloat16, 'fp16': torch.float16}
TOL = {'bf16': (0.01, 0.01), 'fp16': (0.001, 0.001)}
OPS = ('rms_norm', 'rmsnorm2d_fwd', 'rmsnorm2d_fwd_with_add')
ENV = ('CK_TILE_RMSNORM_DIE_MODE', 'CK_TILE_RMSNORM_DIE_CHUNK',
       'CK_TILE_RMSNORM_DIE_MASK')
WIDTHS = (10, 64, 126, 128, 256, 512, 640, 768, 1024, 1152,
          1536, 2048, 3071, 3072, 4094, 4096, 6143, 6144, 8190, 8192,
          8193, 8194, 8204, 8200)
# Fixed matrix widths whose selected CK tile has an even thread buffer.
# Physical gfx936/gfx938 use cast_tile_pk_fp16_fp32's explicit RTZ conversion.
FP16_PACKED_CAST_WIDTHS = frozenset(WIDTHS) - {10, 3071}


@contextmanager
def config(mode='auto', chunk=1, mask=0):
    previous = {k: os.environ.get(k) for k in ENV}
    for k, v in zip(ENV, (mode, chunk, mask)):
        os.environ[k] = str(v)
    try:
        yield
    finally:
        for k, v in previous.items():
            if v is None:
                os.environ.pop(k, None)
            else:
                os.environ[k] = v


def query_xcds():
    """HSA topology evidence; launch decisions independently use HIP numXcc."""
    class Agent(ctypes.Structure):
        _fields_ = [('handle', ctypes.c_uint64)]
    hsa = ctypes.CDLL(ctypes.util.find_library('hsa-runtime64') or 'libhsa-runtime64.so.1')
    callback = ctypes.CFUNCTYPE(ctypes.c_uint32, Agent, ctypes.c_void_p)
    hsa.hsa_agent_get_info.argtypes = (Agent, ctypes.c_int, ctypes.c_void_p)
    hsa.hsa_iterate_agents.argtypes = (callback, ctypes.c_void_p)
    records = []

    @callback
    def visit(agent, unused):
        device = ctypes.c_uint32()
        status = hsa.hsa_agent_get_info(agent, 17, ctypes.byref(device))
        if status or device.value != 1:
            return status
        xcds = ctypes.c_uint32()
        status = hsa.hsa_agent_get_info(agent, 0xA111, ctypes.byref(xcds))
        if not status:
            records.append(xcds.value)
        return status
    if hsa.hsa_init():
        raise RuntimeError('hsa_init failed')
    try:
        if hsa.hsa_iterate_agents(visit, None):
            raise RuntimeError('HSA XCD query failed')
    finally:
        hsa.hsa_shut_down()
    return records


def case(op, n, m=None, **kw):
    # More than one TG even for the small-N configurations, with a row tail.
    return dict(op=op, m=m if m is not None else (9 if n <= 768 else 3), n=n,
                mode='auto', chunk=1, pattern='random', inplace=False,
                epsilon=1e-6 if n % 2 == 0 else 1e-5, **kw)


def cases(suite):
    if suite in ('quick', 'full'):
        result = [case(op, n) for op in OPS for n in (128, 8200)]
        if suite == 'full':
            for op in (OPS[1], OPS[2]):
                result.extend(case(op, n) for n in WIDTHS if n not in (128, 8200))
                for n, pattern in ((64, 'zero'), (8192, 'small')):
                    c = case(op, n); c['pattern'] = pattern; result.append(c)
            result += [case(OPS[0], 126), case(OPS[0], 8193)]
            for n in (128, 2048, 8200):
                c = case(OPS[2], n); c['inplace'] = True; result.append(c)
        return result
    if suite == 'multi':
        result = []
        for op in OPS:
            for m, mode, chunk in ((1, 'auto', 1), (17, 'linear', 2), (9, 'off', 1)):
                c = case(op, 128, m); c.update(mode=mode, chunk=chunk); result.append(c)
        return result
    if suite == 'route':
        result = []
        for op in OPS:
            c = case(op, 128, 17); c.update(mode='linear', chunk=2); result.append(c)
        # A two-pass fused residual dispatch also needs execution on both XCDs.
        c = case(OPS[2], 8200, 3); c.update(mode='linear', chunk=1); result.append(c)
        return result
    return []


def fp16_rtz(value):
    """Independent CPU round-toward-zero conversion for finite FP32 values."""
    nearest = value.half()
    overshoot = nearest.float().abs() > value.abs()
    bits = nearest.view(torch.int16).clone()
    # For either sign, decrementing the FP16 encoding steps toward zero.
    bits[overshoot] -= 1
    return bits.view(torch.float16)


def reference(x, residual, weight, epsilon, fused, residual_rtz=False):
    if not fused:
        value = x.float()
        ref = value * torch.rsqrt(value.square().mean(-1, keepdim=True) + epsilon) * weight.float()
        return ref, None
    value = x.float() + residual.float()
    stored = fp16_rtz(value) if residual_rtz else value.to(x.dtype)
    if x.dtype == torch.bfloat16:
        # Existing CK PRE_ADD_STORE rounds the sum, normalized value and product.
        value = stored.float()
    inv_rms = torch.rsqrt(value.square().mean(-1, keepdim=True) + epsilon)
    # The two-pass kernel rereads residual_out for its numerator.
    numerator = stored.float() if x.shape[-1] > 8192 else value
    scaled = numerator * inv_rms
    if x.dtype == torch.bfloat16:
        scaled = scaled.to(x.dtype).float()
        return (scaled * weight.float()).to(x.dtype).float(), stored
    return scaled * weight.float(), stored


def run_case(aiter, name, c):
    m, n = c['m'], c['n']
    dtype = DTYPES[name]
    gen = torch.Generator().manual_seed(20261027 + n + m)
    x = (torch.randn(m, n, generator=gen) + torch.arange(m).view(-1, 1) * 0.125).to(dtype)
    residual = (torch.randn(m, n, generator=gen) * 0.5).to(dtype)
    weight = (0.5 + torch.rand(n, generator=gen)).to(dtype)
    if c['pattern'] == 'zero':
        x.zero_(); residual.zero_()
    elif c['pattern'] == 'small':
        x = (x.float() * 1e-4).to(dtype)
        residual = (residual.float() * 1e-4).to(dtype)
    fused = c['op'] == OPS[2]
    arch = torch.cuda.get_device_properties(0).gcnArchName.split(':')[0]
    residual_rtz = (fused and dtype == torch.float16 and arch in ('gfx936', 'gfx938')
                    and n in FP16_PACKED_CAST_WIDTHS)
    ref, ref_residual = reference(x, residual, weight, c['epsilon'], fused, residual_rtz)
    dx, dw = x.cuda(), weight.cuda()
    dr = residual.cuda() if fused else None
    with config(c['mode'], c['chunk']):
        if fused:
            out = dx if c['inplace'] else torch.full_like(x, float('nan')).cuda()
            rout = dr if c['inplace'] else torch.full_like(residual, float('nan')).cuda()
            returned = aiter.rmsnorm2d_fwd_with_add(out, dx, dr, rout, dw, c['epsilon'])
            assert returned is None, 'with_add must return None'
        else:
            out = getattr(aiter, c['op'])(dx, dw, c['epsilon'])
        torch.cuda.synchronize()
    assert out.shape == x.shape and out.dtype == dtype and out.device == dx.device
    actual = out.cpu().float()
    rtol, atol = TOL[name]
    error = (actual-ref).abs()
    limit = atol + rtol*ref.abs()
    bad = ~(error <= limit)
    if bool(bad.any()) or not bool(torch.isfinite(actual).all()):
        raise AssertionError(f'{int(bad.sum())} mismatches; per_row={bad.sum(1).tolist()}; '
                             f'max_abs={float(error.max())}; max_ratio={float((error/limit).max())}')
    assert torch.equal(dw.cpu(), weight), 'weight modified'
    if not c['inplace']:
        assert out.data_ptr() != dx.data_ptr(), 'unexpected output alias'
        assert torch.equal(dx.cpu(), x), 'input modified'
    if fused:
        assert torch.equal(rout.cpu(), ref_residual), 'residual_out differs from rounded sum'
        if not c['inplace']:
            assert torch.equal(dr.cpu(), residual), 'residual_in modified'
    return dict(max_abs_error=float(error.max()), max_tolerance_ratio=float((error/limit).max()),
                residual_exact=fused,
                residual_rounding=('rtz' if residual_rtz else 'rne') if fused else None)


def invalid_cases(aiter, single=False):
    x = torch.ones(1, 128, dtype=torch.bfloat16).cuda()
    weight = torch.ones(128, dtype=torch.bfloat16).cuda()
    configs = [('linear', 1, 0, 'at least 2 reported XCDs')] if single else [
        ('bad', 1, 0, 'DIE_MODE'), ('linear', 0, 0, 'DIE_CHUNK'),
        ('linear', -1, 0, 'DIE_CHUNK'), ('linear', 'abc', 0, 'DIE_CHUNK'),
        ('linear', 1, 1, 'DIE_MASK'), ('linear', 1, 2, 'DIE_MASK')]
    result = []
    for mode, chunk, mask, expected in configs:
        with config(mode, chunk, mask):
            try:
                aiter.rmsnorm2d_fwd(x, weight, 1e-6)
                torch.cuda.synchronize()
            except (RuntimeError, ValueError) as exc:
                if expected not in str(exc):
                    raise
                result.append(dict(mode=mode, chunk=chunk, mask=mask, rejected=True, error=str(exc)))
            else:
                raise AssertionError(f'configuration was accepted: {mode}/{chunk}/{mask}')
    return result


def main():
    parser = argparse.ArgumentParser(description=__doc__, formatter_class=argparse.RawDescriptionHelpFormatter)
    parser.add_argument('--suite', choices=('quick', 'full', 'multi', 'route', 'invalid', 'single-reject'), default='quick',
                        help='case matrix (default: quick); invalid/single-reject exercise rmsnorm2d_fwd only')
    parser.add_argument('--ops', nargs='+', choices=OPS, default=list(OPS),
                        help='public APIs to test (default: all); rejection suites require rmsnorm2d_fwd')
    parser.add_argument('--dtypes', nargs='+', choices=DTYPES, default=list(DTYPES),
                        help='input/weight dtypes (default: bf16 fp16); rejection suites use bf16')
    parser.add_argument('--require-arch', default='gfx946', help='required device architecture (default: gfx946)')
    parser.add_argument('--expect-xcds', type=int, help='assert one HSA device with N XCDs; does not set topology')
    parser.add_argument('--json', type=Path, help='write per-case JSON results; parent directory must exist')
    parser.add_argument('--resume', type=Path, help='optionally reuse completed results with identical identity')
    parser.add_argument('--rebuild', action='store_true',
                        help='rebuild module_rmsnorm from the current AITER/CK sources before testing')
    parser.add_argument('--widths', nargs='+', type=int, help='select only these N values')
    args = parser.parse_args()
    if args.suite in ('invalid', 'single-reject') and 'rmsnorm2d_fwd' not in args.ops:
        parser.error('invalid/single-reject exercise rmsnorm2d_fwd; include it in --ops')
    selected = [c for c in cases(args.suite) if c['op'] in args.ops
                and (not args.widths or c['n'] in args.widths)]
    if args.suite not in ('invalid', 'single-reject') and not selected:
        parser.error('no cases match --ops/--widths in the selected suite')
    torch.set_num_threads(1)
    props = torch.cuda.get_device_properties(0)
    assert props.gcnArchName.split(':')[0] == args.require_arch, props
    topology = query_xcds() if args.expect_xcds is not None else None
    if topology is not None:
        assert topology == [args.expect_xcds], topology
    import aiter
    from aiter.jit import core
    module = None
    if not args.rebuild:
        try:
            module = core.get_module('module_rmsnorm')
        except ModuleNotFoundError:
            pass
    if module is None:
        # Use the installed AITER build configuration; no extra GPU warmup call.
        build = core.get_args_of_build('module_rmsnorm')
        build['md_name'] = 'module_rmsnorm'
        core.build_module(**{k: v for k, v in build.items()
                             if k in inspect.signature(core.build_module).parameters})
        module = core.get_module('module_rmsnorm')
    so = Path(module.__file__).resolve()
    identity = dict(arch=props.gcnArchName, topology=topology,
                    module=str(so), sha256=hashlib.sha256(so.read_bytes()).hexdigest(),
                    test_sha256=hashlib.sha256(Path(__file__).read_bytes()).hexdigest(),
                    gpu_chip=os.environ.get('GPU_CHIP'), gpu_args=os.environ.get('GPU_ARGS'),
                    torch=torch.__version__, hip=torch.version.hip)
    # Runtime launcher must not depend on the PMD selector after initialization.
    os.environ.pop('GPU_CHIP', None)
    result = dict(identity=identity, suite=args.suite, ops=args.ops, cases=[], complete=False)
    print('IDENTITY '+json.dumps(identity), flush=True)
    reused = {}
    if args.resume:
        old = json.loads(args.resume.read_text())
        assert old['identity'] == identity and old['complete'], 'resume identity mismatch'
        reused = {r['id']: r for r in old['cases'] if r['status'] == 'PASS'}

    def save(record):
        result['cases'].append(record)
        print(record['status']+' '+json.dumps(record), flush=True)
        if args.json:
            args.json.write_text(json.dumps(result, indent=2)+'\n')

    for name in args.dtypes:
        for c in selected:
            key = name+'_'+hashlib.sha256(json.dumps(c, sort_keys=True).encode()).hexdigest()[:16]
            if key in reused:
                save(dict(reused[key], reused=True)); continue
            print('START '+name+' '+json.dumps(c), flush=True)
            record = dict(id=key, dtype=name, **c)
            try:
                save(dict(record, status='PASS', **run_case(aiter, name, c)))
            except Exception as exc:
                save(dict(record, status='FAIL', error=str(exc)))
                raise
    if args.suite in ('invalid', 'single-reject'):
        for i, r in enumerate(invalid_cases(aiter, args.suite == 'single-reject')):
            save(dict(id=f'reject_{i}', status='PASS', **r))
    result['complete'] = True
    if args.json:
        args.json.write_text(json.dumps(result, indent=2)+'\n')
    print(f"RESULT PASS {len(result['cases'])} cases", flush=True)


if __name__ == '__main__':
    main()
