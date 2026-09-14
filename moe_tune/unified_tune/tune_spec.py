# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
# SPDX-License-Identifier: MIT
"""定义与校验统一 MoE 调优输入。

规范化 shape、dtype、量化参数及 token 列表，兼容旧 CSV；
生成任务身份、后端能力限制和原生配置文件名。"""
import csv
import hashlib
import json
from dataclasses import asdict, dataclass, replace

DEFAULT_TOKENS = (1, 2, 4, 8, 16, 24, 32, 64, 128, 256, 512, 1024, 2048, 4096, 8192, 16384, 32768)
QUANTS = {
    "int8_w8a8_channel": ("int8_channel", "int8_w8a8", "tuned_fmoe_asm_w8a8_channel"),
    "f8_w8a8_channel": ("fp8_channel", "fp8_w8a8", "tuned_fmoe_asm_w8a8_channel"),
    "no_quant": ("bf16", None, "tuned_fmoe_asm"),
    "int8_w8a8_block": ("int8", "int8_w8a8", "tuned_fmoe_asm_w8a8_group"),
    "f8_w8a8_block": ("fp8", "fp8_w8a8", "tuned_fmoe_asm_w8a8_group"),
    "int4_w4a16": ("int4", "int4_w4a16", "tuned_fmoe_asm_w4a16"),
    "int4_w4a8": ("int4int8", "int4_w4a8", "tuned_fmoe_asm_w4a8_group"),
    "int4_w4a8_channel": ("int4int8_channel", "int4_w4a8", None),
    "int8_w8a16": ("bf16", "int8_w8a16", None),
}
DTYPES = {"fp16": "fp16", "f16": "fp16", "float16": "fp16", "torch.float16": "fp16",
          "bf16": "bf16", "bfloat16": "bf16", "torch.bfloat16": "bf16"}


def digest(value):
    return hashlib.sha256(json.dumps(value, sort_keys=True, separators=(",", ":")).encode()).hexdigest()


def tokens_from_string(value):
    try:
        values = tuple(sorted(set(int(x.strip()) for x in str(value).split(","))))
    except ValueError as exc:
        raise ValueError("tokens must be a comma-separated list of positive integers") from exc
    if not values or min(values) < 1:
        raise ValueError("tokens must be positive")
    return values


def log_shape_progress(spec, m, backend, progress=None, stage="TUNE"):
    """打印逐 M 进度；序号仅用于展示，不改变 shape 的调优身份。"""
    progress = progress or {}
    shape_index = progress.get("shape_offset", 0) + spec.tokens.index(m) + 1
    shape_total = progress.get("shape_total", len(spec.tokens))
    backend_index = progress.get("backend_index", 1)
    backend_total = progress.get("backend_total", 1)
    print(f"[shape {shape_index}/{shape_total}][backend {backend_index}/{backend_total}: {backend}][{stage}]\n"
          f"M={m} I={spec.inter_dim} D={spec.model_dim} E={spec.experts} topk={spec.topk} "
          f"quant={spec.quant_type} dtype={spec.dtype}", flush=True)


@dataclass(frozen=True)
class TuneSpec:
    tokens: tuple
    inter_dim: int
    model_dim: int
    experts: int
    topk: int
    quant_type: str = "int8_w8a8_channel"
    dtype: str = "fp16"
    activation: str = "silu"
    shuffle: int = 0
    seed: int = 0
    q_size_n: int = None
    q_size_k: int = None
    has_zp: int = None

    def __post_init__(self):
        object.__setattr__(self, "tokens", tokens_from_string(",".join(map(str, self.tokens))))
        if self.dtype not in DTYPES:
            raise ValueError(f"unsupported dtype {self.dtype!r}; choose fp16 or bf16")
        object.__setattr__(self, "dtype", DTYPES[self.dtype])
        if self.quant_type not in QUANTS:
            raise ValueError(f"unsupported quant_type {self.quant_type!r}; supported: {', '.join(QUANTS)}")
        for name in ("inter_dim", "model_dim", "experts", "topk"):
            if type(getattr(self, name)) is not int or getattr(self, name) < 1:
                raise ValueError(f"{name} must be a positive integer")
        if self.topk > self.experts:
            raise ValueError("topk must not exceed experts")
        if self.activation != "silu":
            raise ValueError("this release supports gated silu only")
        if self.shuffle not in (0, 1):
            raise ValueError("shuffle must be 0 or 1")
        if self.seed < 0:
            raise ValueError("seed must be nonnegative")
        if max(self.tokens) > 32768:
            raise ValueError("use per-chunk tokens <=32768; larger runtime inputs are chunked by Triton")
        block = self.quant_type.endswith('_block')
        group = self.quant_type in ('int4_w4a16', 'int4_w4a8')
        for name, default in (('q_size_n', 128 if block else 0),
                              ('q_size_k', 128 if block else 64 if group else 0),
                              ('has_zp', int(group))):
            if getattr(self, name) is None:
                object.__setattr__(self, name, default)
            if type(getattr(self, name)) is not int:
                raise ValueError(f'{name} must be an integer')
        if self.has_zp not in (0, 1) or (self.has_zp and not group):
            raise ValueError('has-zp is supported only for INT4 group quantization')
        if block:
            if (self.q_size_n, self.q_size_k) != (128, 128):
                raise ValueError('W8A8 block currently requires q-size-n=128 and q-size-k=128')
        elif group:
            if self.q_size_n != 0 or self.q_size_k not in (32, 64, 128):
                raise ValueError('INT4 group requires q-size-n=0 and q-size-k=32/64/128')
            if self.quant_type == 'int4_w4a8' and (self.q_size_k != 64 or not self.has_zp):
                raise ValueError('W4A8 group currently requires group 64 and explicit zero points')
        elif self.q_size_n != 0 or self.q_size_k != 0:
            raise ValueError('channel/no_quant requires q-size-n=q-size-k=0')
        if (block or group) and any(d % self.q_size_k for d in (self.inter_dim, self.model_dim)):
            raise ValueError('inter-dim and model-dim must be divisible by the quantization block/group size')
        if self.quant_type.startswith('int4') and any(d % 2 for d in (self.inter_dim, self.model_dim)):
            raise ValueError('INT4 packed weights require even inter-dim and model-dim')

    @property
    def block_shape(self):
        return [self.q_size_n, self.q_size_k] if self.q_size_k else None

    def backend_error(self, backend):
        if backend == 'asm':
            if QUANTS[self.quant_type][2] is None:
                return f'ASM has no native tuning/config path for {self.quant_type}; use --backend triton'
            if self.quant_type.startswith('int4'):
                if self.shuffle:
                    return 'ASM INT4 shuffle is not supported by this native path'
                if self.q_size_k != 64 or not self.has_zp:
                    return 'ASM INT4 tunable CSV path requires group 64 and explicit zero points; group 32 uses a fixed specialized solution'
                if any(d % 128 for d in (self.inter_dim, self.model_dim)):
                    return 'ASM INT4 zero-point packing requires inter-dim/model-dim divisible by 128'
        return None

    def to_dict(self):
        return asdict(self)

    @property
    def case_id(self):
        return digest(self.to_dict())[:16]

    def semantic_key(self, backend):
        data = self.to_dict()
        data.pop("tokens")
        data.pop("seed")
        if backend == "triton":
            data.pop("shuffle")
        return digest(data)

    def asm_filename(self):
        if QUANTS[self.quant_type][2] is None:
            raise ValueError(self.backend_error('asm'))
        return QUANTS[self.quant_type][2] + ("_shuffle" if self.shuffle else "") + ".csv"

    def triton_filenames(self, arch):
        dtype = QUANTS[self.quant_type][1]
        name = f"E={self.experts},N={self.inter_dim},arch={arch}"
        if dtype:
            name += f",dtype={dtype}"
        block = f',block_shape=[{self.q_size_n},{self.q_size_k}]' if self.q_size_n and self.q_size_k else ''
        return name + block + ".json", name + ",is_bottom=True" + block + ".json"


def read_specs(args):
    shape_names = ("tokens", "inter_dim", "model_dim", "experts", "topk", "quant_type", "dtype", 'q_size_n', 'q_size_k', 'has_zp')
    if args.tp_size != 1 or args.ep_size != 1:
        raise ValueError("TP/EP orchestration is not supported; supply actual local tensor shapes with TP=EP=1")
    if args.input_file:
        if any(getattr(args, name) is not None for name in shape_names):
            raise ValueError("--input-file is mutually exclusive with single-shape/dtype/quant options")
        specs = []
        with open(args.input_file, newline="", encoding="utf-8-sig") as stream:
            reader = csv.DictReader(stream)
            required = {"token", "inter_dim", "model_dim", "expert", "topk", "quant_type", "indtype"}
            if not required.issubset(reader.fieldnames or []):
                raise ValueError(f"CSV requires columns: {', '.join(sorted(required))}")
            for rowno, row in enumerate(reader, 2):
                if not any(str(v or "").strip() for v in row.values()):
                    continue
                try:
                    quant_options = {q: int(row[q]) if row.get(q) else None
                                     for q in ('q_size_n', 'q_size_k', 'has_zp')}
                    # Legacy ASM shape CSVs store 0/0 even when their old tuner
                    # internally uses fixed block 128 or INT4 group 64.
                    if (row['quant_type'].endswith('_block') or row['quant_type'] in ('int4_w4a16', 'int4_w4a8')):
                        if not quant_options['q_size_n'] and not quant_options['q_size_k']:
                            quant_options.update(q_size_n=None, q_size_k=None)
                    specs.append(TuneSpec(tokens=tokens_from_string(row["token"]),
                        inter_dim=int(row["inter_dim"]), model_dim=int(row["model_dim"]),
                        experts=int(row["expert"]), topk=int(row["topk"]),
                        quant_type=row["quant_type"], dtype=row["indtype"],
                        activation=args.activation, shuffle=args.shuffle, seed=args.seed,
                        **quant_options))
                except (ValueError, TypeError) as exc:
                    raise ValueError(f"CSV row {rowno}: {exc}") from exc
    else:
        if any(getattr(args, name) is None for name in ("inter_dim", "model_dim", "experts", "topk")):
            raise ValueError("specify --inter-dim, --model-dim, --experts and --topk (or --input-file)")
        specs = [TuneSpec(tokens=tokens_from_string(args.tokens) if args.tokens else DEFAULT_TOKENS,
            inter_dim=args.inter_dim, model_dim=args.model_dim, experts=args.experts, topk=args.topk,
            quant_type=args.quant_type or "int8_w8a8_channel", dtype=args.dtype or "fp16",
            activation=args.activation, shuffle=args.shuffle, seed=args.seed,
            q_size_n=args.q_size_n, q_size_k=args.q_size_k, has_zp=args.has_zp)]
    # Combine CSV rows of the same shape, preserving every explicitly requested M.
    combined = {}
    for spec in specs:
        key = spec.to_dict(); key.pop("tokens"); key = digest(key)
        old = combined.get(key)
        combined[key] = replace(spec, tokens=tuple(sorted(set(spec.tokens + (old.tokens if old else ())))))
    if not combined:
        raise ValueError("input has no shapes")
    return list(combined.values())
