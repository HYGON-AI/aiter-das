# SPDX-License-Identifier: MIT
# Copyright (c) 2026 Hygon Information Technology Co., Ltd.
#
# Weight layout markers, offline layout query, and one-shot weight preparation
# for fused_moe.
#
#   layout: raw (no shuffle) / marlin (moe_c) / asm_shuffle (asm), decided once
#   by ``decide_layout`` at load time; the prepare step only executes it.
#
#   Runtime layout has a single source: the ``prepared`` object returned by
#   ``fused_moe_prepare_weights``. Without ``prepared``, weights are treated as
#   raw. Tensor markers (``weight_layout`` attribute) are only cross-checked: a
#   conflicting marker raises; tensors that are not the prepared pair warn once
#   and still run with ``prepared.layout``.
#
#   ``fused_moe_prepare_weights`` returns ``(w1p, w2p, prepared)``. ``prepared``
#   is a frozen dataclass holding layout, processed scales, prepare-time
#   signature, decision details, arch and CU count; it keeps weakrefs to the
#   weights only, so it adds no device memory. Weights stay with the caller.
#
#   Passing already-shuffled weights (marlin / asm_shuffle marker) back into the
#   prepare step raises: shuffle changes weight shapes, so deciding on them again
#   describes a non-existent original problem. Same pair plus same params hit a
#   weakref-only cache.
#
#   No module-level import of fused_moe / fused_moe_router (circular import);
#   import them inside functions when needed.
"""Weight layout markers, offline layout query, and one-shot preparation API."""

import logging
import os
import weakref
from dataclasses import dataclass

import torch

WEIGHT_LAYOUT_ATTR = "weight_layout"

RAW = "raw"
MARLIN = "marlin"
ASM_SHUFFLE = "asm_shuffle"

VALID_LAYOUTS = (RAW, MARLIN, ASM_SHUFFLE)

logger = logging.getLogger(__name__)


def _tensor_marker(t: torch.Tensor):
    """Return the ``weight_layout`` attribute, or None when missing.

    None and ``raw`` are different states: clone / detach / ``.to()`` /
    serialize roundtrip all produce objects without the attribute.
    """
    return getattr(t, WEIGHT_LAYOUT_ATTR, None)


def get_weight_layout(w1, w2=None) -> str:
    """Read the layout marker of a prepared weight pair; missing/None -> RAW.

    Raises when w1/w2 carry DIFFERENT markers (a half-shuffled pair is a
    configuration error, never a legal routing state).
    """
    l1 = _tensor_marker(w1) or RAW
    if w2 is None:
        if l1 not in VALID_LAYOUTS:
            raise ValueError(f"unknown weight_layout {l1!r} on w1")
        return l1
    l2 = _tensor_marker(w2) or RAW
    if l1 != l2:
        raise ValueError(
            f"fused_moe weight layout mismatch: w1={l1!r} w2={l2!r} "
            "(prepare both weights together via fused_moe_prepare_weights)")
    if l1 not in VALID_LAYOUTS:
        raise ValueError(f"unknown weight_layout {l1!r}")
    return l1


def _mark(w1, w2, layout):
    """Set the ``weight_layout`` attribute on the prepare output (only writer)."""
    for t in (w1, w2):
        setattr(t, WEIGHT_LAYOUT_ATTR, layout)


_ENUM_NAME_IMPL = None
_QUANT_TYPE_CLS = None
_ACTIVATION_TYPE_CLS = None


def _enum_name(value, enum_cls) -> str:
    """Reuse fused_moe's enum-name normalization; cache it (import costs ~3 us)."""
    global _ENUM_NAME_IMPL
    impl = _ENUM_NAME_IMPL
    if impl is None:
        from aiter.fused_moe import _enum_name as impl_fn
        impl = _ENUM_NAME_IMPL = impl_fn
    return impl(value, enum_cls)


def _quant_name(quant_type):
    global _QUANT_TYPE_CLS
    # None and QuantType.No are the same state (unquantized) -> "no"
    if quant_type is None:
        return "no"
    cls = _QUANT_TYPE_CLS
    if cls is None:
        from aiter import QuantType
        cls = _QUANT_TYPE_CLS = QuantType
    return _enum_name(quant_type, cls)


def _activation_name(activation):
    global _ACTIVATION_TYPE_CLS
    if activation is None:
        return "none"
    cls = _ACTIVATION_TYPE_CLS
    if cls is None:
        from aiter import ActivationType
        cls = _ACTIVATION_TYPE_CLS = ActivationType
    return _enum_name(activation, cls)


def _expert_count(expert_mask, w1) -> int:
    """Global expert count: mask length for EP, else ``w1.shape[0]`` (shuffle keeps dim 0)."""
    return int(expert_mask.numel()) if expert_mask is not None else int(w1.shape[0])


@dataclass(frozen=True)
class PrepareSignature:
    """Prepare-time parameter signature; runtime params are compared field by field."""

    quant_type: str
    quant_type_a: str | None
    quant_dtype_a: str | None
    dtype: str
    topk: int
    activation: str
    is_ep: bool
    num_experts: int
    splitk: int
    block_size_M: int | None
    # prepare-only fields, not compared at runtime
    backend: str
    max_num_tokens: int | None

    def diff(self, other: "PrepareSignature"):
        """Return human-readable mismatches (empty list when identical)."""
        out = []
        for name in ("quant_type", "quant_type_a", "quant_dtype_a", "dtype",
                     "topk", "activation", "is_ep", "num_experts", "splitk",
                     "block_size_M"):
            mine, theirs = getattr(self, name), getattr(other, name)
            if mine != theirs:
                out.append(f"{name}：准备时 {mine!r}，运行时 {theirs!r}")
        return out


def _build_signature(quant_type, quant_type_a, quant_dtype_a, dtype, topk,
                     activation, expert_mask, splitk, block_size_M, backend,
                     max_num_tokens, w1):
    return PrepareSignature(
        quant_type=_quant_name(quant_type),
        quant_type_a=None if quant_type_a is None else _quant_name(quant_type_a),
        quant_dtype_a=None if quant_dtype_a is None else str(quant_dtype_a),
        dtype=str(dtype),
        topk=int(topk),
        activation=_activation_name(activation),
        is_ep=expert_mask is not None,
        num_experts=_expert_count(expert_mask, w1),
        splitk=int(splitk or 0),
        block_size_M=int(block_size_M) if block_size_M else None,
        backend=str(backend),
        max_num_tokens=None if max_num_tokens is None else int(max_num_tokens),
    )


@dataclass(frozen=True, eq=False)
class PreparedMoe:
    """Read-only result of ``fused_moe_prepare_weights`` (weights excluded).

    ``layout`` is the only effective layout source and cannot be reassigned.
    Scales are the processed versions: raw unchanged, marlin passthrough, asm
    ``w2_scale`` padded to ``padded_k``, per_Tensor expanded to per_channel.
    Holds weakrefs to the weights only, to detect whether the runtime pair is
    still the prepared one; no device memory is kept.
    """

    __slots__ = ("layout", "w1_scale", "w2_scale", "signature", "decision",
                 "arch", "cu_num", "_w1_ref", "_w2_ref", "__weakref__")

    layout: str
    w1_scale: "torch.Tensor | None"
    w2_scale: "torch.Tensor | None"
    signature: PrepareSignature
    decision: "LayoutDecision"
    arch: str
    cu_num: int
    _w1_ref: "weakref.ReferenceType"
    _w2_ref: "weakref.ReferenceType"

    def same_weights(self, w1, w2) -> bool:
        """True when ``(w1, w2)`` is still the prepared pair (weakref compare)."""
        return self._w1_ref() is w1 and self._w2_ref() is w2

    # Immutable object: copy / deepcopy return self. Rebuilding it through the
    # frozen __setattr__ raises FrozenInstanceError, and duplicating the scales
    # is pointless while costing memory.
    def __copy__(self):
        return self

    def __deepcopy__(self, memo):
        return self


# (id(w1), id(w2), signature) -> weakrefs to (w1, w2, w1p, w2p, prepared).
# A hit requires every ref to be alive and the in-refs to be the passed pair.
_PREPARE_CACHE = {}
_PREPARE_CACHE_LIMIT = 1024


def _cache_get(w1, w2, signature):
    key = (id(w1), id(w2), signature)
    ent = _PREPARE_CACHE.get(key)
    if ent is None:
        return None
    in1, in2, out1, out2, prepared = (r() for r in ent)
    if in1 is not w1 or in2 is not w2 or out1 is None or out2 is None \
            or prepared is None:
        _PREPARE_CACHE.pop(key, None)
        return None
    return out1, out2, prepared


def _cache_put(w1, w2, signature, o1, o2, prepared):
    if len(_PREPARE_CACHE) >= _PREPARE_CACHE_LIMIT:
        dead = [k for k, v in _PREPARE_CACHE.items() if any(r() is None for r in v)]
        for k in dead:
            _PREPARE_CACHE.pop(k, None)
    _PREPARE_CACHE[(id(w1), id(w2), signature)] = tuple(
        weakref.ref(t) for t in (w1, w2, o1, o2, prepared))


def resolve_weight_layout(w1, w2, explicit=None) -> str:
    """Resolve the layout used inside ``_normalize_problem``.

    An explicit string is the effective layout; ``None`` reads the tensor marker
    and defaults to raw. Marker conflict handling lives in
    ``resolve_runtime_weights``; here only pair consistency and validity are
    checked.
    """
    attr = get_weight_layout(w1, w2)
    if explicit is None:
        return attr
    if explicit not in VALID_LAYOUTS:
        raise ValueError(
            f"fused_moe: unknown weight_layout {explicit!r} "
            f"(valid: {VALID_LAYOUTS})")
    return explicit


# Prepared objects already warned about (once per object, dropped on release)
_WARNED_PREPARED = weakref.WeakSet()

# Last runtime params that passed validation, per prepared object; skips
# rebuilding the signature (entries disappear with the object)
_CHECKED_RUNTIME = weakref.WeakKeyDictionary()

# device index -> (arch, cu_num); both are constants within a process
_DEVICE_META = {}


def _current_device_meta():
    """(arch, cu_num) of the current device, cached per device index."""
    from aiter.jit.utils.chip_info import get_cu_num, get_gfx

    idx = torch.cuda.current_device()
    meta = _DEVICE_META.get(idx)
    if meta is None:
        meta = (get_gfx(), int(get_cu_num()))
        _DEVICE_META[idx] = meta
    return meta


def _warn_prepared_once(prepared):
    if os.environ.get("AITER_FMOE_PREPARED_WARN", "1") == "0":
        return
    if prepared in _WARNED_PREPARED:
        return
    _WARNED_PREPARED.add(prepared)
    logger.warning(
        "fused_moe: 传入的权重不是 fused_moe_prepare_weights 返回的那一对"
        "（可能做过 clone、换设备或重新加载），现按 prepared.layout=%r 执行；"
        "如果权重或缩放系数与该对象不对应，结果可能出错；"
        "改动权重后请重新调用准备函数。", prepared.layout)


def _check_signature(prepared, quant_type, quant_type_a, quant_dtype_a, dtype,
                     topk, activation, expert_mask, splitk, block_size_M, w1):
    """Compare runtime params with the prepare-time signature; raise naming the fields."""
    runtime = _build_signature(
        quant_type, quant_type_a, quant_dtype_a, dtype, topk, activation,
        expert_mask, splitk, block_size_M, prepared.signature.backend,
        prepared.signature.max_num_tokens, w1)
    diffs = prepared.signature.diff(runtime)
    if diffs:
        raise ValueError(
            "fused_moe: 运行期参数与 fused_moe_prepare_weights 时不一致（"
            + "；".join(diffs) + "）；请按准备时的参数调用，或重新准备")


def resolve_runtime_weights(w1, w2, prepared, w1_scale, w2_scale, *,
                            topk, activation, quant_type, dtype,
                            expert_mask=None, splitk=0, block_size_M=None,
                            quant_type_a=None, quant_dtype_a=None):
    """Resolve the effective scales and layout at runtime.

    Checks, in order: a single scale source, matching w1/w2 markers, device
    identity, runtime params vs the prepare-time signature, marker vs
    ``prepared.layout``, and a one-time warning when the tensors are not the
    prepared pair. Returns ``(w1_scale, w2_scale, layout)``.
    """

    # scales come from exactly one source: prepared, or the caller
    if prepared is not None and (w1_scale is not None or w2_scale is not None):
        raise ValueError(
            "fused_moe: prepared 与 w1_scale / w2_scale 不能同时传入；"
            "缩放系数只能有一个来源，传了 prepared 就使用它携带的缩放系数")

    # w1/w2 markers must agree; a half-shuffled pair is a config error
    m1 = _tensor_marker(w1)
    m2 = _tensor_marker(w2)
    if m1 != m2:
        raise ValueError(
            f"fused_moe weight layout mismatch: w1={m1!r} w2={m2!r} "
            "(prepare both weights together via fused_moe_prepare_weights)")
    if m1 is not None and m1 not in VALID_LAYOUTS:
        raise ValueError(
            f"fused_moe: unknown weight_layout marker {m1!r} "
            f"(valid: {VALID_LAYOUTS})")

    if prepared is None:
        # no prepare step: weights are declared as raw
        if m1 in (None, RAW):
            return w1_scale, w2_scale, RAW
        raise ValueError(
            f"fused_moe: 权重带 {m1!r} 布局标记（已重排过），但没有传 prepared；"
            "请把 fused_moe_prepare_weights 返回的 prepared 传给 fused_moe")

    # device guard: prepare and run must share arch and CU count, since tuning
    # tables are keyed by both. Skipped while tracing: get_gfx reads rocminfo /
    # KFD sysfs (subprocess and filesystem), which breaks the graph under
    # fullgraph compile; compiled code is rebuilt per device anyway.
    if not torch.compiler.is_compiling():
        arch, cu_num = _current_device_meta()
        if prepared.arch != arch or prepared.cu_num != cu_num:
            raise ValueError(
                f"fused_moe: prepared 是在 {prepared.arch} / {prepared.cu_num} CU 上"
                f"准备的，当前设备是 {arch} / {cu_num} CU；请在目标设备上重新准备")

    # signature check: the same object with the same raw params hits the fast
    # path (comparing 10 scalars is cheaper than rebuilding and formatting).
    # While tracing, always build the signature: values are constants there and
    # no weakrefs should be created during capture.
    if torch.compiler.is_compiling():
        _check_signature(prepared, quant_type, quant_type_a, quant_dtype_a,
                         dtype, topk, activation, expert_mask, splitk,
                         block_size_M, w1)
    else:
        runtime_key = (
            topk, activation, quant_type, quant_type_a, quant_dtype_a, dtype,
            expert_mask is not None, _expert_count(expert_mask, w1),
            int(splitk or 0), int(block_size_M) if block_size_M else None)
        if _CHECKED_RUNTIME.get(prepared) != runtime_key:
            _check_signature(prepared, quant_type, quant_type_a, quant_dtype_a,
                             dtype, topk, activation, expert_mask, splitk,
                             block_size_M, w1)
            _CHECKED_RUNTIME[prepared] = runtime_key

    # marker must match the effective layout; raw marker on a marlin object is
    # a conflict too
    if m1 is not None and m1 != prepared.layout:
        raise ValueError(
            f"fused_moe: 权重标记 {m1!r} 与 prepared.layout="
            f"{prepared.layout!r} 冲突；请传入准备函数返回的那一对权重，"
            "或从原始权重重新准备")

    # tensors are not the prepared pair: warn once, then run prepared.layout.
    # Test is_compiling first to avoid tracing the weakref call.
    if not torch.compiler.is_compiling() and not prepared.same_weights(w1, w2):
        _warn_prepared_once(prepared)
    return prepared.w1_scale, prepared.w2_scale, prepared.layout


def _build_problem(w1, w2, quant_type, dtype, topk, activation, expert_mask,
                   w1_scale=None, w2_scale=None, block_size_M=None,
                   doweight_stage1=False, splitk=0, quant_type_a=None,
                   quant_dtype_a=None):
    """用权重形状构造 FusedMoeProblem（不依赖激活张量，M 固定 1）。"""
    from aiter.fused_moe import _normalize_problem

    return _normalize_problem(
        hidden_states=None,
        w1=w1,
        w2=w2,
        topk_ids=None,
        expert_mask=expert_mask,
        activation=activation,
        quant_type=quant_type,
        quant_type_a=quant_type_a,
        quant_dtype_a=quant_dtype_a,
        block_size_M=block_size_M,
        doweight_stage1=doweight_stage1,
        splitk=splitk,
        w1_scale=w1_scale,
        w2_scale=w2_scale,
        M=1,
        topk=topk,
        dtype=dtype,
    )


def _shuffle_kind(problem):
    """Map FusedMoeProblem to the family vocabulary of ``_shared_shuffle_impl``."""
    kind = problem.quant_kind
    if kind == "w8a8":
        return "w8a8_fp8" if problem.q_dtype_a == "fp8" else "w8a8_int8"
    if kind == "w8a8_block":
        return "w8a8_fp8" if problem.q_dtype_a == "fp8" else "w8a8_int8"
    if kind == "none":
        return "none"
    return kind


def _prepared_scales(w1, w2, problem, w1_scale, w2_scale):
    """Expand per_Tensor scales to per_channel at prepare time.

    Must run before shuffle: asm padding changes ``w2`` geometry to ``padded_k``,
    after which the original K is no longer available.
    """
    if problem.quant_kind == "w8a8" and problem.quant_type == "per_tensor":
        from aiter.fused_moe import _per_tensor_to_channel_scale

        w1_scale = _per_tensor_to_channel_scale(
            w1_scale, w1.shape[0], w1.shape[1], "w1_scale")
        w2_scale = _per_tensor_to_channel_scale(
            w2_scale, w2.shape[0], w2.shape[1], "w2_scale")
    return w1_scale, w2_scale


def describe_fused_moe_layout(
    w1: torch.Tensor,
    w2: torch.Tensor,
    quant_type=None,
    w1_scale=None,
    w2_scale=None,
    dtype=torch.bfloat16,
    topk=8,
    activation="silu",
    expert_mask=None,
    backend="auto",
    max_num_tokens=None,
    block_size_M=None,
    doweight_stage1=False,
    splitk=0,
    quant_type_a=None,
    quant_dtype_a=None,
):
    """Read-only layout query (no shuffle, no weight mutation).

    Returns a dict with layout / family / reason / padded_k / original_k /
    feasible_layouts / weighted_gain / quant_kind / arch / shape /
    current_marker.
    """
    from aiter.fused_moe_router import decide_layout, feasible_layouts

    problem = _build_problem(
        w1, w2, quant_type, dtype, topk, activation, expert_mask,
        w1_scale=w1_scale, w2_scale=w2_scale, block_size_M=block_size_M,
        doweight_stage1=doweight_stage1, splitk=splitk,
        quant_type_a=quant_type_a, quant_dtype_a=quant_dtype_a)
    dec = decide_layout(problem, backend=backend, max_num_tokens=max_num_tokens)
    feasible = feasible_layouts(problem)
    return {
        "layout": dec.layout,
        "family": dec.family,
        "reason": dec.reason,
        "padded_k": dec.padded_k,
        "original_k": dec.original_k,
        "feasible_layouts": sorted(feasible),
        "weighted_gain": dec.weighted_gain,
        "quant_kind": problem.quant_kind,
        "arch": problem.arch,
        "shape": {
            "E": problem.E,
            "local_E": problem.local_E,
            "inter_dim": problem.inter_dim,
            "model_dim": problem.model_dim,
            "topk": problem.topk,
        },
        "current_marker": get_weight_layout(w1, w2),
    }


def fused_moe_prepare_weights(
    w1: torch.Tensor,
    w2: torch.Tensor,
    quant_type=None,
    w1_scale=None,
    w2_scale=None,
    dtype=torch.bfloat16,
    topk=8,
    activation="silu",
    expert_mask=None,
    backend="auto",
    max_num_tokens=None,
    block_size_M=None,
    doweight_stage1=False,
    splitk=0,
    quant_type_a=None,
    quant_dtype_a=None,
):
    """Shuffle ``w1`` / ``w2`` once according to the decision.

    Returns ``(w1p, w2p, prepared)``. ``prepared`` is the read-only
    ``PreparedMoe``: effective layout, processed scales (raw unchanged, marlin
    passthrough, asm ``w2_scale`` padded to ``padded_k``, per_Tensor expanded to
    per_channel), prepare-time signature, decision details, arch and CU count.
    Forward must pass ``prepared=prepared`` and use ``prepared.w1_scale`` /
    ``prepared.w2_scale``.

    Repeat calls with the same original pair and params hit the cache and return
    the same objects (no second shuffle); changed params re-prepare from the
    originals. Already-shuffled weights (marlin / asm_shuffle marker) raise:
    shuffle changes shapes, so deciding again describes a non-existent original
    problem. No forced-layout entry; tests that need it call
    ``aiter.moe._shared_shuffle_impl`` directly.
    """
    from aiter.fused_moe_router import decide_layout
    from aiter.jit.utils.chip_info import get_cu_num

    # already-shuffled input is rejected; get_weight_layout also checks the pair
    pair = get_weight_layout(w1, w2)
    if pair in (MARLIN, ASM_SHUFFLE):
        raise ValueError(
            f"fused_moe_prepare_weights: 输入权重已是 {pair!r} 布局（重排过）；"
            "重排改变了权重形状，不能基于重排后的数据再次准备，"
            "请从原始权重重新准备")

    signature = _build_signature(
        quant_type, quant_type_a, quant_dtype_a, dtype, topk, activation,
        expert_mask, splitk, block_size_M, backend, max_num_tokens, w1)
    hit = _cache_get(w1, w2, signature)
    if hit is not None:
        return hit

    problem = _build_problem(
        w1, w2, quant_type, dtype, topk, activation, expert_mask,
        w1_scale=w1_scale, w2_scale=w2_scale, block_size_M=block_size_M,
        doweight_stage1=doweight_stage1, splitk=splitk,
        quant_type_a=quant_type_a, quant_dtype_a=quant_dtype_a)
    dec = decide_layout(problem, backend=backend, max_num_tokens=max_num_tokens)
    layout = dec.layout
    if layout not in VALID_LAYOUTS:
        raise ValueError(f"fused_moe_prepare_weights: bad decision layout {layout!r}")

    logger.info(
        "fused_moe prepare: quant_kind=%s arch=%s E=%d N=%d K=%d topk=%d "
        "layout=%s family=%s padded_k=%s reason=%s",
        problem.quant_kind, problem.arch, problem.E, problem.inter_dim,
        problem.model_dim, problem.topk, layout, dec.family, dec.padded_k,
        dec.reason)

    s1, s2 = _prepared_scales(w1, w2, problem, w1_scale, w2_scale)
    if layout == RAW:
        o1, o2 = w1, w2
    else:
        from aiter.moe import _shared_shuffle_impl

        o1, o2, s1, s2 = _shared_shuffle_impl(
            w1, w2, s1, s2,
            quant_kind=_shuffle_kind(problem), padded_k=dec.padded_k,
            block_shape=problem.block_shape, layout=layout)

    _mark(o1, o2, layout)
    prepared = PreparedMoe(
        layout=layout,
        w1_scale=s1,
        w2_scale=s2,
        signature=signature,
        decision=dec,
        arch=problem.arch,
        cu_num=int(get_cu_num()),
        _w1_ref=weakref.ref(o1),
        _w2_ref=weakref.ref(o2),
    )
    _cache_put(w1, w2, signature, o1, o2, prepared)
    return o1, o2, prepared
