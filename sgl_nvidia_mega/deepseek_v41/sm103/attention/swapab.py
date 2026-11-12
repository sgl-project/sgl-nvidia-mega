# SPDX-License-Identifier: Apache-2.0
# SPDX-FileCopyrightText: Copyright (c) 2026 NVIDIA CORPORATION & AFFILIATES. All rights reserved.
# Adapted from SGLang's python/sglang/kernels/ops/attention/dsv4/decode_attention_sm100.py (Apache-2.0).
"""SM100 small-batch paged attention with the heads on the MMA N dimension; the
caller applies the output's inverse RoPE (the fused wo_a does)."""

import torch
import triton
import triton.language as tl

from .kv_layout import KVLayout

LAYOUT = KVLayout.V4
MAX_BATCH = 8
# Each (row, KV tile) is its own CTA, so rows past MAX_BATCH are a caller's dispatch choice.
WIDE_MAX_BATCH = 64
NUM_HEADS = 16  # the MMA's head columns
# Local query heads served: 16 at attention TP4, 8 at TP8 (padded to 16 in the MMA)
HEAD_COUNTS = (8, 16)
HEAD_DIM = 512
# With pdl, trigger the next kernel (wo_a_fused streams its weights before its wait) right
# after the wait, not after the loads: faster in 7 of 9 GB300 micro-bench cases at 6-24 rows.
COMBINE_EARLY_TRIGGER = True
SOFTMAX_SCALE = HEAD_DIM**-0.5
# combine_counter: a row's tile CTAs wait for each other, so a launch takes it only when
# every CTA fits on its own SM; past this deadline a waiting CTA traps instead of hanging
FUSED_WAIT_DEADLINE_NS = 2_000_000_000
# per-CTA %globaltimer stamps (bench only): [rows * tiles, STAMP_SLOTS] int64
STAMP_SLOTS = 16


@triton.jit
def _combine(
    PART,
    MAX,
    SUM,
    SINK,
    OUT,
    NT: tl.constexpr,
    ST: tl.constexpr,
    H: tl.constexpr,
    BD: tl.constexpr,
    USE_GDC: tl.constexpr,
    EARLY_TRIGGER: tl.constexpr,
    ENTRY_TRIGGER: tl.constexpr = False,
):
    b, h, tile = tl.program_id(0), tl.program_id(1), tl.program_id(2)
    t, d = tl.arange(0, ST), tile * BD + tl.arange(0, BD)
    if USE_GDC:
        if ENTRY_TRIGGER:
            # The consumer reads OUT only after its own grid wait; launching it now lets
            # it stream its weights while the partial kernel still runs.
            tl.extra.cuda.gdc_launch_dependents()
        tl.extra.cuda.gdc_wait()
        if EARLY_TRIGGER and not ENTRY_TRIGGER:
            tl.extra.cuda.gdc_launch_dependents()
    den = tl.load(SUM + (b * NT + t) * H + h, t < NT, 0)
    mx = tl.load(MAX + (b * NT + t) * H + h, t < NT, 0)
    mx = tl.where(den > 0, mx, -float("inf"))
    sink = tl.load(SINK + h)
    m = tl.maximum(tl.max(mx, 0), sink)
    m = tl.where(tl.abs(m) == float("inf"), 0.0, m)
    factor = tl.exp(mx - m)
    denominator = tl.sum(den * factor, 0) + tl.exp(sink - m)
    vals = tl.load(
        PART + ((b * NT + t[:, None]) * H + h) * 512 + d[None, :],
        t[:, None] < NT,
        0,
    )
    if USE_GDC and not EARLY_TRIGGER and not ENTRY_TRIGGER:
        tl.extra.cuda.gdc_launch_dependents()
    out = tl.sum(vals * factor[:, None], 0) / denominator
    out = tl.where((denominator > 0) & (sink != float("inf")), out, 0.0)
    out = out.to(OUT.dtype.element_ty)
    tl.store(OUT + (b * H + h) * 512 + d, out)


_SM_COUNT: dict = {}


def fused_combine_fits(rows: int, tiles: int, device) -> bool:
    """Whether a launch of ``rows`` x ``tiles`` CTAs can merge in the kernel: all of
    them resident at once, one per SM."""
    index = torch.device(device).index
    if index is None:
        index = torch.cuda.current_device()
    if index not in _SM_COUNT:
        _SM_COUNT[index] = torch.cuda.get_device_properties(index).multi_processor_count
    return rows * tiles <= _SM_COUNT[index]


# Cluster merge (slot attn_cluster_merge): a row's tiles as one cluster of NT CTAs that
# merge through distributed shared memory. Where it engages (GB300, attention half bench,
# us per layer, 6 rows): 8 heads, low-ratio range (10 tiles) -1.2..-1.5; 16 heads +0.5..+1.2
# (its 124 KB CTAs need ten free SMs of one GPC beside wq_b's 64 CTAs and launch late);
# window only (2 tiles) +0.5..+0.7 (two CTAs merge all units). At most 8 rows: one wave.
# Served (TP8 + EP2, batch 1, nsys): partial 8.6 vs 5.7 + combine 1.7, wo_a 2.6 vs 3.5 us
# per low-ratio layer; no step gain.
CLUSTER_HEADS = (8,)
CLUSTER_MIN_TILES = 4
CLUSTER_MAX_TILES = 16  # the hardware's largest (non-portable) cluster
CLUSTER_MAX_ROWS = 8


def cluster_merge_takes(rows: int, tiles: int, heads: int) -> bool:
    """Whether ``cluster_merge`` merges a launch of ``rows`` x ``tiles`` CTAs on ``heads``
    local heads in the kernel (elsewhere it keeps the separate combine)."""
    return (
        heads in CLUSTER_HEADS
        and 0 < rows <= CLUSTER_MAX_ROWS
        and CLUSTER_MIN_TILES <= tiles <= CLUSTER_MAX_TILES
    )


def cluster_merge_shape(tiles: int, heads: int) -> tuple[int, int, int]:
    """(rounds, stats offset, exchange bytes) of a cluster merge: each CTA merges at
    most ``rounds * 4`` of the row's ``heads * 4`` 128-column units."""
    rounds = triton.cdiv(triton.cdiv(heads * 4, tiles), 4)
    units = rounds * 4 * tiles * 128 * 4
    return rounds, units, units + tiles * 16 * 4 * 2


_CLUSTER_READY: dict = {}


def _cluster_kernel(fn, args, kwargs, tiles: int, exchange: int):
    """The compiled ``fn`` for these arguments, set to launch ``tiles``-CTA clusters
    with ``exchange`` bytes of dynamic shared memory past the compiler's own; returns
    (kernel, exchange offset). The compiler's shared memory does not depend on XOFF."""
    kernel = fn.warmup(*args, grid=(1,), **kwargs)
    kernel._init_handles()
    ready = _CLUSTER_READY.get(id(kernel))
    if ready is not None and ready[0] is kernel:
        return kernel, ready[1]
    from cuda.bindings import driver as cu

    num_warps, num_ctas, shared = kernel.packed_metadata
    assert num_ctas == 1, "the kernel is compiled for single-CTA launches"
    xoff = -(-shared // 16) * 16
    total = xoff + exchange
    func = cu.CUfunction(kernel.function)
    attrs = [
        (cu.CUfunction_attribute.CU_FUNC_ATTRIBUTE_MAX_DYNAMIC_SHARED_SIZE_BYTES, total)
    ]
    if tiles > 8:
        attrs.append(
            (
                cu.CUfunction_attribute.CU_FUNC_ATTRIBUTE_NON_PORTABLE_CLUSTER_SIZE_ALLOWED,
                1,
            )
        )
    for attr, value in attrs:
        (err,) = cu.cuFuncSetAttribute(func, attr, value)
        assert err == cu.CUresult.CUDA_SUCCESS, f"cuFuncSetAttribute({attr}): {err}"
    # Triton's launcher multiplies grid x by num_ctas and sets the cluster dimension
    kernel.packed_metadata = (num_warps, tiles, total)
    _CLUSTER_READY[id(kernel)] = (kernel, xoff)
    return kernel, xoff


def _launch_cluster(fn, rows, args, kwargs, tiles, exchange):
    kernel, xoff = _cluster_kernel(fn, args, {**kwargs, "XOFF": 0}, tiles, exchange)
    bound = dict(zip(fn.arg_names, args))
    bound.update(kwargs, XOFF=xoff)
    values = [bound[p.name] if p.name in bound else p.default for p in fn.params]
    kernel[(rows, 1, 1)](*values)


def _q_rope_kwargs(q_rope, b):
    freqs, positions = q_rope
    assert (
        freqs.dtype == torch.float32 and freqs.shape[-1] == 64 and freqs.is_contiguous()
    )
    assert positions.shape == (b,)
    return {"FREQS": freqs, "POS": positions, "ROPE_Q": True}


def swapab_attention(
    q,
    kv,
    indices,
    lengths,
    sink,
    extra_kv=None,
    extra_indices=None,
    extra_lengths=None,
    *,
    max_rows=MAX_BATCH,
    pdl=False,
    narrow_combine=False,
    q_rope=None,
    kv_before_wait=False,
    combine_entry_trigger=False,
    extra_after_wait=False,
    combine_counter=None,
    stage_before_wait=False,
    stamps=None,
    wait_deadline_ns=FUSED_WAIT_DEADLINE_NS,
    cluster_merge=False,
    force_cluster=False,
):
    """V4-layout attention on 16 (TP4) or 8 (TP8) heads; `extra_*` is a second slot range appended
    to each request's keys, and the attention sink is folded in exactly once.
    `pdl` launches both kernels as programmatic dependents; `narrow_combine` runs the
    combine as one-warp programs over 128 columns. `q_rope` = (fp32 [pos, 64] freqs,
    positions [b]) applies the query RoPE as Q loads. `kv_before_wait` gathers the KV
    rows before the PDL wait: the caller guarantees that only Q is still in flight.
    `extra_after_wait` (with `kv_before_wait`): only the window rows are gathered before
    the wait; the extra range's indices and lengths come from the PDL predecessor (the
    layer's top-k). `combine_entry_trigger` launches the combine's dependent at the
    combine's entry.
    `stage_before_wait` (with `kv_before_wait`; slot attn_prewait): 1 also loads the
    query's RoPE row before the wait, 2 also stages the KV tile in shared memory.
    `combine_counter` (int32 [>= rows], zero, owned by one call site) merges the tiles
    inside the attention kernel when every CTA fits on its own SM: the narrow combine's
    arithmetic, no second launch; not in the chain (its row barrier measured slower than
    the second launch, benchmark/bench_deepseek_v41_attn_half.py). `stamps` (int64
    [rows * tiles, STAMP_SLOTS]) records per-CTA %globaltimer phases for benchmarks.
    `cluster_merge` (slot attn_cluster_merge; with `narrow_combine`, where
    `cluster_merge_takes`): each row's tiles run as one cluster and merge through
    distributed shared memory inside the attention kernel, bit for bit the narrow
    combine, with no second launch; the kernel's dependents launch at its entry.
    `force_cluster` (tests) merges in the cluster wherever the hardware allows."""
    from .swapab_gluon import partial_gluon  # Gluon imports only where it runs

    block = 64
    b, h, d = q.shape[0], q.shape[-2], q.shape[-1]
    assert q.ndim in (3, 4) and (q.ndim == 3 or q.shape[1] == 1)
    assert 0 < b <= min(max_rows, WIDE_MAX_BATCH) and h in HEAD_COUNTS and d == HEAD_DIM
    assert q.dtype == torch.bfloat16 and q.stride(-1) == 1
    assert kv.shape[-1] == LAYOUT.bytes_per_token
    assert kv.dtype in (torch.uint8, torch.float8_e4m3fn)
    assert indices.stride(-1) == 1 and lengths.is_contiguous()
    assert sink.stride(0) == 1 and sink.numel() >= h
    nk = indices.shape[-1]
    ne = 0 if extra_indices is None else extra_indices.shape[-1]
    assert block in (32, 64, 128) and nk > 0
    if extra_kv is None:
        assert extra_indices is None and extra_lengths is None
        extra_kv, extra_indices, extra_lengths = kv, indices, lengths
    else:
        assert extra_kv.shape[-1] == LAYOUT.bytes_per_token
        assert extra_kv.dtype in (torch.uint8, torch.float8_e4m3fn)
        assert extra_indices.stride(-1) == 1 and extra_lengths.is_contiguous()
    kv, extra_kv = kv.view(torch.uint8), extra_kv.view(torch.uint8)
    kt = triton.cdiv(nk, block)
    nt = kt + triton.cdiv(ne, block)
    partial = torch.empty((b, nt, h, 512), dtype=torch.float32, device=q.device)
    maximum = torch.empty((b, nt, h), dtype=torch.float32, device=q.device)
    sums = torch.empty_like(maximum)
    out = torch.empty((b, h, 512), dtype=q.dtype, device=q.device)
    fused = (
        combine_counter is not None
        and narrow_combine
        and fused_combine_fits(b, nt, q.device)
    )
    if fused:
        assert combine_counter.dtype == torch.int32 and combine_counter.numel() >= b
        st = triton.next_power_of_2(nt)
        rounds = triton.cdiv(triton.cdiv(h * 4, nt), 4)
        fused_kwargs = dict(
            FUSED=True,
            CNT=combine_counter,
            SINK=sink,
            OUT=out,
            DEADLINE=wait_deadline_ns,
            ST=st,
            ROUNDS=rounds,
        )
    else:
        fused_kwargs = {}
    if stamps is not None:
        assert stamps.dtype == torch.int64 and stamps.numel() >= b * nt * STAMP_SLOTS
    cluster = (
        cluster_merge
        and narrow_combine
        and not fused
        and (
            cluster_merge_takes(b, nt, h)
            or (force_cluster and b <= CLUSTER_MAX_ROWS and nt <= CLUSTER_MAX_TILES)
        )
    )
    args = (
        q,
        kv,
        extra_kv,
        indices,
        extra_indices,
        lengths,
        extra_lengths,
        partial,
        maximum,
        sums,
    )
    kwargs = dict(
        QS=q.stride(0),
        QH=q.stride(-2),
        IS=indices.stride(0),
        EIS=extra_indices.stride(0),
        KP=kv.shape[1],
        KS=kv.stride(0),
        EP=extra_kv.shape[1],
        ES=extra_kv.stride(0),
        NK=nk,
        NE=ne,
        NT=nt,
        KT=kt,
        BT=block,
        H=NUM_HEADS,
        SCALE=SOFTMAX_SCALE,
        KTOKENS=kv.shape[0] * kv.shape[1],
        ETOKENS=extra_kv.shape[0] * extra_kv.shape[1],
        COMPENSATE=True,
        SWAP_AB=True,
        DATA_BYTES=LAYOUT.data_bytes,
        SCALE_BYTES=LAYOUT.scale_bytes,
        TILE=LAYOUT.tile_size,
        num_warps=4,
        **({"USE_GDC": True, "launch_pdl": True} if pdl else {}),
        **(_q_rope_kwargs(q_rope, b) if q_rope is not None else {}),
        **({"KV_BEFORE_WAIT": True} if pdl and kv_before_wait else {}),
        **({"HQ": h} if h != NUM_HEADS else {}),
        **(
            {"EXTRA_AFTER_WAIT": True}
            if pdl and kv_before_wait and extra_after_wait and ne and not fused
            else {}
        ),
        **(
            {"STAGE_BEFORE_WAIT": int(stage_before_wait)}
            if pdl and kv_before_wait and stage_before_wait
            else {}
        ),
        **fused_kwargs,
        **({"STAMPS": True, "STAMP": stamps} if stamps is not None else {}),
    )
    if cluster:
        rounds, xstats, exchange = cluster_merge_shape(nt, h)
        kwargs.update(
            CLUSTER=True,
            SINK=sink,
            OUT=out,
            ST=triton.next_power_of_2(nt),
            ROUNDS=rounds,
            XSTATS=xstats,
        )
        _launch_cluster(partial_gluon, b, args, kwargs, nt, exchange)
        return out
    partial_gluon[(nt, b) if fused else (b, nt)](*args, **kwargs)
    if fused:
        return out
    bd = 64 if ne else 512
    combine_warps = 4
    if narrow_combine and ne:
        # GB300, 10 KV tiles: 2.1 vs 3.1 us at 12 rows, 2.5 vs 4.6 at 24 (BD 64 / 4 warps).
        bd, combine_warps = 128, 1
    _combine[(b, h, triton.cdiv(512, bd))](
        partial,
        maximum,
        sums,
        sink,
        out,
        NT=nt,
        ST=triton.next_power_of_2(nt),
        H=h,
        BD=bd,
        USE_GDC=pdl,
        EARLY_TRIGGER=COMBINE_EARLY_TRIGGER,
        **({"ENTRY_TRIGGER": True} if pdl and combine_entry_trigger else {}),
        num_warps=combine_warps,
        **({"launch_pdl": True} if pdl else {}),
    )
    return out
