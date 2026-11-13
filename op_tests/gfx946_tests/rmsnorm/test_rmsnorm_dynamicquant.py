# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
"""RMSNorm动态量化正确性测试：CPU参考，每个数值用例只调用一次GPU算子。

默认测试有/无残差两个入口，不进行warmup或性能循环。需要已配置好的HIP/PMD
与AITER环境；默认检查gfx946，可用--require-arch gfx938验收其数值路径。
FP16残差参考匹配当前CK实例：gfx938的偶数线程缓冲区使用packed RTZ转换，
本矩阵N10/3071走标量RNE；当前gfx946 PMD按实测RNE检查。两者均精确检查残差，
量化值和scale的容差保持一致，不因残差舍入模式而放宽。

命令行参数（也可用 -h / --help 查看）：
  --suite {quick,full,multi,route,invalid,single-reject}
    选择测试集合，默认quick。以下例数按默认两种输入和两种输出dtype计算：
    quick         16例：N128/8192的基本数值、scale及残差写回检查。
    full         148例：包含quick，增加13个N分桶、尾部、零/混合零/小值、
                 原地残差写回与一维scale布局。
    multi         24例：在多XCD环境检查单TG auto回退、linear/chunk2和off。
    route         24例：5TG auto、9TG linear/chunk2、5TG大N的数值检查；
                 --dtypes bf16可缩减为12例。还需启用PMD统计，并在脚本外
                 检查每个dispatch的各XCD completedWGs；数值PASS不代表路由PASS。
    invalid       14例：非法mode/chunk/mask、N>8192、输出/scale dtype应报错。
                 使用多XCD环境，固定BF16输入与INT8基线，不受dtype筛选影响。
    single-reject  2例：在单XCD环境检查两个入口显式linear均报错；固定BF16/
                 INT8，不受dtype筛选影响。
  --dtypes {bf16,fp16} [...]
    输入及weight的dtype，可选一个或多个；默认bf16 fp16。
  --ops {rmsnorm2d_fwd_with_dynamicquant,rmsnorm2d_fwd_with_add_dynamicquant} [...]
    选择一个或两个公开入口，默认两个都测试；也作用于拒绝测试，例数相应减少。
  --qdtypes {int8,fp8} [...]
    量化输出dtype，可选一个或多个；默认int8 fp8。fp8指torch.float8_e4m3fn。
  --require-arch {gfx946,gfx938,gfx936}
    要求实际设备架构与此值一致，默认gfx946。真机仅支持quick/full数值集合，
    不查询gfx946专用XCD拓扑，也不宣称验证了多die路由。
    gfx936须同时指定--qdtypes int8。
  --expect-xcds N
    校验HSA拓扑恰为一个设备、N个XCD；仅用于gfx946，未指定则不做此额外断言。
    只检查拓扑，不设置die数；PMD的1/2/4 XCD由启动前的GPU_CHIP=sb/sbx2/sbx4选择。
  --json PATH
    把模块路径/哈希、环境身份及逐例结果写入PATH，每个用例后更新；最终标记
    complete=true。默认只打印，不写JSON；PATH的父目录须已存在。
  --resume PATH
    从已完整结束的JSON复用匹配的PASS数值用例，例如quick结果用于full。
    脚本及helper哈希、SO路径/哈希、架构/拓扑和记录的环境必须完全一致；
    不接受未完成的JSON，也不复用invalid/single-reject检查。默认全部实际执行。
  --rebuild
    测试前用当前AITER/CK源码重新构建module_rmsnorm。默认先加载已有模块，
    缺失时自动构建；修改native源码后应显式重建。五个RMSNorm入口共用此模块，
    只需重建一次，无需额外构建脚本。

环境已配置时，在任意新建的结果目录中运行，例如：
  AITER_REPO=/path/to/aiter  # 按实际源码根目录修改
  TEST="$AITER_REPO/op_tests/gfx946_tests/rmsnorm/test_rmsnorm_dynamicquant.py"
  GPU_CHIP=sb python "$TEST" --suite quick --expect-xcds 1 --json quick.json
  GPU_CHIP=sb python "$TEST" --suite full --expect-xcds 1 --resume quick.json --json full.json
  GPU_CHIP=sbx4 GPU_DFLAGS="['StatLog','TT0']" python "$TEST" --suite route --dtypes bf16 --expect-xcds 4 --json route.json

脚本初始化HIP后会移除GPU_CHIP，验证launcher依据实际HIP拓扑分流。
测试集合内部设置mode/chunk/mask，无需另行设置CK_TILE_RMSNORM_DIE_*。
只依赖同目录test_rmsnorm.py和正常的AITER/CK、PyTorch及HIP环境；不需要
历史测试结果或任务目录。完整环境配置与逐算子命令见同目录README.md。
"""
import argparse
import hashlib
import inspect
import json
import os
from pathlib import Path

import torch
from test_rmsnorm import config, query_xcds, fp16_rtz

DTYPES = {'bf16': torch.bfloat16, 'fp16': torch.float16}
QTYPES = {'int8': torch.int8, 'fp8': torch.float8_e4m3fn}
OPS = ('rmsnorm2d_fwd_with_dynamicquant', 'rmsnorm2d_fwd_with_add_dynamicquant')
WIDTHS = (10, 126, 128, 256, 512, 640, 768, 1024, 1152, 1536,
          2048, 3071, 4094, 6143, 8192)
# generate.py selects even-sized thread buffers for these fixed matrix widths.
# N10 and N3071 select scalar casts (one and three elements per thread).
FP16_PACKED_CAST_WIDTHS = frozenset(WIDTHS) - {10, 3071}


def case(op, n, **kw):
    c = dict(op=op, n=n, m=33 if n <= 128 else 5, mode='auto', chunk=1,
             pattern='random', inplace=False, flat_scale=False, epsilon=1e-5)
    c.update(kw)
    return c


def cases(suite):
    if suite in ('quick', 'full'):
        result = [case(op, n) for op in OPS for n in (128, 8192)]
        if suite == 'full':
            result += [case(op, n) for op in OPS for n in WIDTHS if n not in (128, 8192)]
            result += [case(op, 128, pattern=p) for op in OPS for p in ('zero', 'mixed', 'small')]
            result += [case(OPS[1], 128, inplace=True, flat_scale=True)]
        return result
    if suite == 'multi':
        return [case(op, 128, m=m, mode=mode, chunk=chunk)
                for op in OPS for m, mode, chunk in
                ((1, 'auto', 1), (33, 'linear', 2), (17, 'off', 1))]
    if suite == 'route':
        return [case(op, n, m=m, mode=mode, chunk=chunk)
                for op in OPS for n, m, mode, chunk in
                ((128, 17, 'auto', 1), (128, 33, 'linear', 2), (8192, 5, 'linear', 1))]
    return []


def reference(x, residual, weight, eps, residual_rtz=False):
    value = x.float() if residual is None else x.float() + residual.float()
    # Dynamic quant keeps FP32 intermediates even for BF16 fused residuals.
    norm = value * torch.rsqrt(value.square().mean(-1, keepdim=True) + eps) * weight.float()
    stored = None if residual is None else fp16_rtz(value) if residual_rtz else value.to(x.dtype)
    return norm, stored


def invoke(aiter, c, out, x, residual, residual_out, scale, weight):
    fn = getattr(aiter, c['op'])
    if c['op'] == OPS[1]:
        ret = fn(out, x, residual, residual_out, scale, weight, c['epsilon'])
    else:
        ret = fn(out, x, scale, weight, c['epsilon'])
    assert ret is None


def run_case(aiter, dtype_name, qname, c):
    dtype, qdtype = DTYPES[dtype_name], QTYPES[qname]
    m, n = c['m'], c['n']
    gen = torch.Generator().manual_seed(20261027 + m + n)
    x = torch.randn(m, n, generator=gen).to(dtype)
    residual = (torch.randn(m, n, generator=gen) * .5).to(dtype)
    weight = (torch.randn(n, generator=gen) * .5 + 1).to(dtype)
    if c['pattern'] == 'zero':
        x.zero_(); residual.zero_()
    elif c['pattern'] == 'mixed':
        x[0].zero_(); residual[0].zero_()
        if m > 1:
            x[1].fill_(1); residual[1].fill_(-1)
    elif c['pattern'] == 'small':
        x = (x.float() * 1e-4).to(dtype)
        residual = (residual.float() * 1e-4).to(dtype)
    fused = c['op'] == OPS[1]
    arch = torch.cuda.get_device_properties(0).gcnArchName.split(':')[0]
    residual_rtz = (fused and dtype == torch.float16 and arch in ('gfx936', 'gfx938')
                    and n in FP16_PACKED_CAST_WIDTHS)
    ref, ref_residual = reference(x, residual if fused else None, weight, c['epsilon'], residual_rtz)
    qmax = 127 if qname == 'int8' else 448
    ref_scale = ref.abs().amax(-1, keepdim=True) / qmax
    scaled = torch.where(ref_scale > 0, ref / ref_scale, torch.zeros_like(ref))
    expected = scaled.to(qdtype).float()  # INT8 truncation; E4M3FN round to nearest.
    dx, dw = x.cuda(), weight.cuda()
    dr = residual.cuda() if fused else None
    rout = (dr if c['inplace'] else torch.full_like(x, float('nan')).cuda()) if fused else None
    # Raw byte sentinels avoid launching a separate GPU initialization kernel.
    out = torch.full((m, n), 0x55, dtype=torch.uint8).view(qdtype).cuda()
    shape = (m,) if c['flat_scale'] else (m, 1)
    ds = torch.full(shape, float('nan'), dtype=torch.float32).cuda()
    with config(c['mode'], c['chunk']):
        invoke(aiter, c, out, dx, dr, rout, ds, dw)
        torch.cuda.synchronize()
    actual = out.cpu().float()
    scale = ds.cpu().reshape(m, 1)
    assert bool(torch.isfinite(actual).all()) and bool(torch.isfinite(scale).all())
    assert bool((scale >= 0).all())
    torch.testing.assert_close(scale, ref_scale, rtol=2e-5, atol=1e-8)
    zero = ref_scale == 0
    assert bool((scale[zero] == 0).all()) and bool((actual[zero.expand_as(actual)] == 0).all())
    if qname == 'int8':
        # Reduction roundoff can cross an integer boundary, including +/-127.
        assert bool(((actual - expected).abs() <= 1).all()), 'INT8 quant mismatch > 1'
        quant_bound = scale * 1.0001 + ref.abs() * 2e-5 + 1e-7
    else:
        # E4M3FN half-ULP bound for every element, including subnormals.
        magnitude = scaled.abs().clamp_min(2.0**-6)
        half_ulp = torch.pow(2.0, torch.floor(torch.log2(magnitude)) - 4)
        assert bool(((actual - scaled).abs() <= half_ulp + scaled.abs()*2e-5 + 1e-6).all()), 'FP8 rounding bound'
        quant_bound = scale * (half_ulp + 1e-6) + ref.abs() * 4e-5 + 1e-7
    assert bool(((actual * scale - ref).abs() <= quant_bound).all()), 'dequantization bound'
    assert torch.equal(dx.cpu(), x) and torch.equal(dw.cpu(), weight), 'input/weight modified'
    if fused:
        assert torch.equal(rout.cpu(), ref_residual), 'residual writeback differs'
        if not c['inplace']:
            assert torch.equal(dr.cpu(), residual), 'residual input modified'
    return dict(max_scale_error=float((scale-ref_scale).abs().max()),
                max_quant_error=float((actual-expected).abs().max()),
                max_dequant_error=float((actual*scale-ref).abs().max()), residual_exact=fused,
                residual_rounding=('rtz' if residual_rtz else 'rne') if fused else None)


def rejections(aiter, single=False, ops=OPS):
    x = torch.ones(17, 128, dtype=torch.bfloat16).cuda()
    w = torch.ones(128, dtype=torch.bfloat16).cuda()
    q = torch.empty_like(x, dtype=torch.int8)
    s = torch.empty((17, 1), dtype=torch.float32, device=x.device)
    r = torch.empty_like(x)
    tests = [('single-linear', 'linear', 1, 0, 'at least 2 reported XCDs')] if single else [
        ('mode', 'bad', 1, 0, 'DIE_MODE'), ('chunk0', 'linear', 0, 0, 'DIE_CHUNK'),
        ('chunk-text', 'linear', 'abc', 0, 'DIE_CHUNK'), ('mask', 'linear', 1, 1, 'DIE_MASK')]
    for op in ops:
        c = case(op, 128)
        for label, mode, chunk, mask, text in tests:
            with config(mode, chunk, mask):
                try:
                    invoke(aiter, c, q, x, x, r, s, w)
                except (RuntimeError, ValueError) as exc:
                    assert text in str(exc), str(exc)
                    yield dict(op=op, check=label, status='PASS', error=str(exc))
                else:
                    raise AssertionError(f'{op}: {label} accepted')
        if single:
            continue
        for label, n, qdtype, sdtype, text in [
            ('width', 8193, torch.int8, torch.float32, 'N <= 8192'),
            ('output', 128, torch.float32, torch.float32, 'output must'),
            ('scale', 128, torch.int8, torch.float16, 'scales must')]:
            xx = torch.ones(1, n, dtype=torch.bfloat16).cuda()
            ww = torch.ones(n, dtype=torch.bfloat16).cuda()
            qq = torch.empty((1, n), dtype=qdtype, device=x.device)
            ss = torch.empty((1, 1), dtype=sdtype, device=x.device)
            try:
                invoke(aiter, c, qq, xx, xx, xx, ss, ww)
            except (RuntimeError, ValueError) as exc:
                assert text in str(exc), str(exc)
                yield dict(op=op, check=label, status='PASS', error=str(exc))
            else:
                raise AssertionError(f'{op}: {label} accepted')


def main():
    parser = argparse.ArgumentParser(description=__doc__, formatter_class=argparse.RawDescriptionHelpFormatter)
    parser.add_argument('--suite', choices=('quick','full','multi','route','invalid','single-reject'), default='quick',
                        help='测试集合，含义及例数见上方说明（默认：quick）')
    parser.add_argument('--ops', nargs='+', choices=OPS, default=list(OPS),
                        help='选择公开入口，也用于拒绝测试（默认：两个入口）')
    parser.add_argument('--dtypes', nargs='+', choices=DTYPES, default=list(DTYPES),
                        help='输入/weight dtype，可多选（默认：bf16 fp16；拒绝测试忽略此项）')
    parser.add_argument('--qdtypes', nargs='+', choices=QTYPES, default=list(QTYPES),
                        help='量化输出dtype，fp8为E4M3FN（默认：int8 fp8；拒绝测试忽略此项）')
    parser.add_argument('--require-arch', choices=('gfx946','gfx938','gfx936'), default='gfx946',
                        help='要求实际架构匹配；真机仅支持quick/full，gfx936须选int8（默认：gfx946）')
    parser.add_argument('--expect-xcds', type=int,
                        help='断言一个设备上有N个XCD；不改变拓扑（默认：不额外断言）')
    parser.add_argument('--json', type=Path,
                        help='逐例写入JSON结果，父目录须已存在（默认：只打印）')
    parser.add_argument('--resume', type=Path,
                        help='复用身份完全一致且已完整结束的JSON中的PASS数值用例（默认：不复用）')
    parser.add_argument('--rebuild', action='store_true',
                        help='测试前用当前AITER/CK源码重建共享的module_rmsnorm（默认：缺失时才构建）')
    args = parser.parse_args()
    if args.require_arch != 'gfx946' and (args.suite not in ('quick','full') or args.expect_xcds is not None):
        parser.error('physical HCU tests only support quick/full without --expect-xcds')
    if args.require_arch == 'gfx936' and 'fp8' in args.qdtypes:
        parser.error('gfx936 requires --qdtypes int8')
    torch.set_num_threads(1)
    props = torch.cuda.get_device_properties(0)
    assert props.gcnArchName.split(':')[0] == args.require_arch, props
    topology = query_xcds() if args.require_arch == 'gfx946' else None
    if args.expect_xcds:
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
        build = core.get_args_of_build('module_rmsnorm'); build['md_name'] = 'module_rmsnorm'
        core.build_module(**{k:v for k,v in build.items() if k in inspect.signature(core.build_module).parameters})
        module = core.get_module('module_rmsnorm')
    so = Path(module.__file__).resolve()
    identity = dict(arch=props.gcnArchName, topology=topology, module=str(so),
                    sha256=hashlib.sha256(so.read_bytes()).hexdigest(),
                    test_sha256=hashlib.sha256(Path(__file__).read_bytes()).hexdigest(),
                    helper_sha256=hashlib.sha256(Path(__file__).with_name('test_rmsnorm.py').read_bytes()).hexdigest(),
                    gpu_chip=os.environ.get('GPU_CHIP'), gpu_args=os.environ.get('GPU_ARGS'),
                    torch=torch.__version__, hip=torch.version.hip)
    os.environ.pop('GPU_CHIP', None)
    result = dict(identity=identity, suite=args.suite, ops=args.ops, cases=[], complete=False)
    print('IDENTITY '+json.dumps(identity), flush=True)
    reused = {}
    if args.resume:
        old = json.loads(args.resume.read_text())
        assert old['identity'] == identity and old['complete'], 'resume identity mismatch'
        reused = {r['id']:r for r in old['cases'] if r['status']=='PASS'}
    def save(record):
        result['cases'].append(record)
        print(record['status']+' '+json.dumps(record), flush=True)
        if args.json:
            args.json.write_text(json.dumps(result, indent=2)+'\n')
    for name in args.dtypes:
        for qname in args.qdtypes:
            for c in cases(args.suite):
                if c['op'] not in args.ops:
                    continue
                key = name+'_'+qname+'_'+hashlib.sha256(json.dumps(c, sort_keys=True).encode()).hexdigest()[:16]
                if key in reused:
                    save(dict(reused[key], reused=True)); continue
                record = dict(id=key, dtype=name, qdtype=qname, **c)
                print('START '+json.dumps(record), flush=True)
                try:
                    save(dict(record, status='PASS', **run_case(aiter,name,qname,c)))
                except Exception as exc:
                    save(dict(record, status='FAIL', error=str(exc)))
                    raise
    for i, rec in enumerate(rejections(aiter, args.suite=='single-reject', args.ops)
                            if args.suite in ('invalid','single-reject') else []):
        save(dict(id=f'reject_{i}', **rec))
    result['complete'] = True
    if args.json:
        args.json.write_text(json.dumps(result, indent=2)+'\n')
    print(f"RESULT PASS {len(result['cases'])} cases", flush=True)


if __name__ == '__main__':
    main()
