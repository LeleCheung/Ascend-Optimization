# Copyright 2026 FlagOS Contributors
# SPDX-License-Identifier: Apache-2.0
"""nan_to_num_ : in-place NaN/+-Inf replacement on Ascend, self-contained Triton.

Reference semantics reproduced:
  * ``A.nan_to_num_(nan, posinf, neginf)`` mutates ``A`` storage in place and
    returns the same tensor object (evaluation observes the mutation of ``A``).
  * ``nan is None``      -> NaN replaced by 0.0
  * ``posinf is None``   -> +Inf replaced by ``finfo(dtype).max``
  * ``neginf is None``   -> -Inf replaced by ``finfo(dtype).min``
  * every other value (including -0.0) passes through bit-exactly.

Device work (unchanged from the measured round 1 kernels, only the constants
are now compile-time):
  1. saturating request (``posinf >= finfo.max`` and ``neginf <= finfo.min``,
     which is what the defaults give) on a 2-byte float dtype: replacing both
     infinities degenerates into a saturating clamp, so ``max(min(x, pos), neg)``
     replaces two compare/select pairs and the kernel stays in the input dtype.
  2. everything else -> fp32-staged compare/select kernel.
  3. non-contiguous -> stride-aware kernels (uniform element stride, or up to
     8D index math); every path reads and writes real storage slots.

Host path (the measured floor: 9 of 12 timing cases are launch-cost bound, flat
at 16.3 us from 4 KiB to 8.4 MB of traffic, while the prebuilt Triton launch
call alone costs 10.1 us and each kernel parameter adds to it):
  * the saturating-default request is the only timed case, so its plan bakes
    ``nan``/``posinf``/``neginf`` defaults into constexpr bounds and keeps just
    one runtime scalar, cutting the launch argument list from five to two
    (measured 11.24 us -> 9.86 us per launch in isolation);
  * ``run`` reduces to one dict get by dtype, one by numel, a pointer-alignment
    test and a contiguity test before firing a prebuilt closure;
  * below ``_SLIM_BYTES`` of traffic the device time is hidden under that host
    floor, so the smaller-tile slim kernel is preferred there; above it the
    device-bound loop kernels are used, which process 2-4 sequential tiles per
    program at one tile of UB and ``num_stages=1`` (measured 58.4 -> 51.5 us for
    float16 and 84.4 -> 77.0 us for float32 on 4096x4096; the double-buffered
    default overflows the 192 KiB UB budget at these tiles).
  * any build failure, unusual dtype, explicit ``nan``/``posinf``/``neginf``,
    non-contiguous or unaligned input falls back to the validated generic path.
"""

import torch
import triton
import triton.language as tl

_BLOCK_MIN = 1024
_BLOCK_TARGET_PROGRAMS = 8
_BLOCK_STAGE = 8192          # validated fp32-staging tile (32 KiB at 4 bytes)
_BLOCK_CLAMP_2B = 16384      # native-dtype tile, 32 KiB at 2 bytes
_BLOCK_STRIDED = 512
_SLIM_BYTES = 4 << 20        # under this traffic the host launch cost dominates

_MAX_DIMS = 8


# --------------------------------------------------------------- device kernels
@triton.jit
def _nan_to_num_stage(a_ptr, n, nan_v, pos_v, neg_v, BLOCK: tl.constexpr):
    offs = tl.program_id(0) * BLOCK + tl.arange(0, BLOCK)
    mask = offs < n
    x = tl.load(a_ptr + offs, mask=mask, other=0.0).to(tl.float32)
    y = tl.where(x != x, nan_v, x)
    y = tl.where(x == float("inf"), pos_v, y)
    y = tl.where(x == float("-inf"), neg_v, y)
    tl.store(a_ptr + offs, y.to(a_ptr.dtype.element_ty), mask=mask)


@triton.jit
def _nan_to_num_clamp(a_ptr, n, nan_v, pos_v, neg_v, BLOCK: tl.constexpr):
    dt = a_ptr.dtype.element_ty
    offs = tl.program_id(0) * BLOCK + tl.arange(0, BLOCK)
    x = tl.load(a_ptr + offs)
    y = tl.maximum(tl.minimum(x, pos_v.to(dt)), neg_v.to(dt))
    y = tl.where(x != x, nan_v.to(dt), y)
    tl.store(a_ptr + offs, y)


@triton.jit
def _nan_to_num_clamp_masked(a_ptr, n, nan_v, pos_v, neg_v, BLOCK: tl.constexpr):
    dt = a_ptr.dtype.element_ty
    offs = tl.program_id(0) * BLOCK + tl.arange(0, BLOCK)
    mask = offs < n
    x = tl.load(a_ptr + offs, mask=mask, other=0.0)
    y = tl.maximum(tl.minimum(x, pos_v.to(dt)), neg_v.to(dt))
    y = tl.where(x != x, nan_v.to(dt), y)
    tl.store(a_ptr + offs, y, mask=mask)


@triton.jit
def _ntn_default(a_ptr, nan_v, POS: tl.constexpr, NEG: tl.constexpr,
                 BLOCK: tl.constexpr):
    """Saturating default, native dtype: identical math to _nan_to_num_clamp
    with the bounds baked in and no length argument (grid covers n exactly)."""
    dt = a_ptr.dtype.element_ty
    offs = tl.program_id(0) * BLOCK + tl.arange(0, BLOCK)
    x = tl.load(a_ptr + offs)
    y = tl.maximum(tl.minimum(x, POS), NEG)
    y = tl.where(x != x, nan_v.to(dt), y)
    tl.store(a_ptr + offs, y)


@triton.jit
def _ntn_default_masked(a_ptr, n, nan_v, POS: tl.constexpr, NEG: tl.constexpr,
                        BLOCK: tl.constexpr):
    dt = a_ptr.dtype.element_ty
    offs = tl.program_id(0) * BLOCK + tl.arange(0, BLOCK)
    mask = offs < n
    x = tl.load(a_ptr + offs, mask=mask, other=0.0)
    y = tl.maximum(tl.minimum(x, POS), NEG)
    y = tl.where(x != x, nan_v.to(dt), y)
    tl.store(a_ptr + offs, y, mask=mask)


@triton.jit
def _ntn_stage_default(a_ptr, nan_v, POS: tl.constexpr, NEG: tl.constexpr,
                       BLOCK: tl.constexpr):
    """Saturating default, fp32-staged compare/select (the measured-fastest
    structure for float32 and for tiles the native clamp cannot fit)."""
    offs = tl.program_id(0) * BLOCK + tl.arange(0, BLOCK)
    x = tl.load(a_ptr + offs).to(tl.float32)
    y = tl.where(x != x, nan_v, x)
    y = tl.where(x == float("inf"), POS, y)
    y = tl.where(x == float("-inf"), NEG, y)
    tl.store(a_ptr + offs, y.to(a_ptr.dtype.element_ty))


@triton.jit
def _ntn_stage_default_masked(a_ptr, n, nan_v, POS: tl.constexpr,
                              NEG: tl.constexpr, BLOCK: tl.constexpr):
    offs = tl.program_id(0) * BLOCK + tl.arange(0, BLOCK)
    mask = offs < n
    x = tl.load(a_ptr + offs, mask=mask, other=0.0).to(tl.float32)
    y = tl.where(x != x, nan_v, x)
    y = tl.where(x == float("inf"), POS, y)
    y = tl.where(x == float("-inf"), NEG, y)
    tl.store(a_ptr + offs, y.to(a_ptr.dtype.element_ty), mask=mask)


@triton.jit
def _ntn_clamp_loop(a_ptr, n, nan_v, pos_v, neg_v, ITERS: tl.constexpr,
                    BLOCK: tl.constexpr):
    """Device-bound regime: ITERS sequential tiles per program at one tile of UB.

    Halving the task count while keeping the measured-fastest tile amortises
    per-task setup; num_stages=1 keeps the loop body from being double buffered
    (which would overflow the 192 KiB UB budget).
    """
    dt = a_ptr.dtype.element_ty
    base = tl.program_id(0) * (ITERS * BLOCK)
    for i in range(ITERS):
        offs = base + i * BLOCK + tl.arange(0, BLOCK)
        mask = offs < n
        x = tl.load(a_ptr + offs, mask=mask, other=0.0)
        y = tl.maximum(tl.minimum(x, pos_v.to(dt)), neg_v.to(dt))
        y = tl.where(x != x, nan_v.to(dt), y)
        tl.store(a_ptr + offs, y, mask=mask)


@triton.jit
def _ntn_stage_loop(a_ptr, n, nan_v, pos_v, neg_v, ITERS: tl.constexpr,
                    BLOCK: tl.constexpr):
    base = tl.program_id(0) * (ITERS * BLOCK)
    for i in range(ITERS):
        offs = base + i * BLOCK + tl.arange(0, BLOCK)
        mask = offs < n
        x = tl.load(a_ptr + offs, mask=mask, other=0.0).to(tl.float32)
        y = tl.where(x != x, nan_v, x)
        y = tl.where(x == float("inf"), pos_v, y)
        y = tl.where(x == float("-inf"), neg_v, y)
        tl.store(a_ptr + offs, y.to(a_ptr.dtype.element_ty), mask=mask)


@triton.jit
def _ntn_cs_loop(a_ptr, n, nan_v, pos_v, neg_v, ITERS: tl.constexpr,
                 BLOCK: tl.constexpr):
    """Compare/select kept entirely in the input dtype (no fp32 staging).

    bfloat16 has no native clamp here (18.1 B/element of UB versus 10.1 for
    float16), so its staged form is capped at an 8192 tile; comparing in the
    native dtype may fit the 16384 tile that float16 already uses.
    """
    dt = a_ptr.dtype.element_ty
    base = tl.program_id(0) * (ITERS * BLOCK)
    for i in range(ITERS):
        offs = base + i * BLOCK + tl.arange(0, BLOCK)
        mask = offs < n
        x = tl.load(a_ptr + offs, mask=mask, other=0.0)
        y = tl.where(x != x, nan_v.to(dt), x)
        y = tl.where(x == float("inf"), pos_v.to(dt), y)
        y = tl.where(x == float("-inf"), neg_v.to(dt), y)
        tl.store(a_ptr + offs, y, mask=mask)


@triton.jit
def _nan_to_num_scaled(a_ptr, n, nan_v, pos_v, neg_v,
                       SCALE: tl.constexpr, BLOCK: tl.constexpr):
    offs = tl.program_id(0) * BLOCK + tl.arange(0, BLOCK)
    mask = offs < n
    idx = offs * SCALE
    x = tl.load(a_ptr + idx, mask=mask, other=0.0).to(tl.float32)
    y = tl.where(x != x, nan_v, x)
    y = tl.where(x == float("inf"), pos_v, y)
    y = tl.where(x == float("-inf"), neg_v, y)
    tl.store(a_ptr + idx, y.to(a_ptr.dtype.element_ty), mask=mask)


@triton.jit
def _nan_to_num_nd(a_ptr, n, nan_v, pos_v, neg_v,
                   s0, s1, s2, s3, s4, s5, s6, s7,
                   t0, t1, t2, t3, t4, t5, t6, t7,
                   NDIM: tl.constexpr, BLOCK: tl.constexpr):
    offs = tl.program_id(0) * BLOCK + tl.arange(0, BLOCK)
    mask = offs < n
    shapes = (s0, s1, s2, s3, s4, s5, s6, s7)
    strides = (t0, t1, t2, t3, t4, t5, t6, t7)
    rem = offs
    off = tl.zeros((BLOCK,), dtype=tl.int32)
    for i in tl.static_range(8):
        if i < NDIM:
            size = shapes[NDIM - 1 - i]
            stride = strides[NDIM - 1 - i]
            off += (rem % size) * stride
            rem = rem // size
    x = tl.load(a_ptr + off, mask=mask, other=0.0).to(tl.float32)
    y = tl.where(x != x, nan_v, x)
    y = tl.where(x == float("inf"), pos_v, y)
    y = tl.where(x == float("-inf"), neg_v, y)
    tl.store(a_ptr + off, y.to(a_ptr.dtype.element_ty), mask=mask)


# ------------------------------------------------------------ host-side plans
_FINFO = {}
_ENTRIES = {}
_EARLY = {}          # dtype -> {numel -> prebuilt default-request closure}
_STREAM = {}
_RAW = None
_EARLY_OK = None
_FAIL = object()

_DEFAULT_LIMITS = {torch.float16: 65504.0,
                   torch.bfloat16: 3.3895313892515355e38,
                   torch.float32: 3.4028234663852886e38}


def _pick_block(n, cap, masked_cap):
    """Elements per program: small tensors keep a small tile, large ones the cap."""
    if n >= cap * _BLOCK_TARGET_PROGRAMS:
        block = cap
    else:
        target = -(-n // _BLOCK_TARGET_PROGRAMS)
        block = _BLOCK_MIN
        while block < target:
            block <<= 1
        if block > cap:
            block = cap
    if n % block and block > masked_cap:
        block = masked_cap
    return block


def _raw_stream_fn():
    """Cheapest faithful current-stream accessor for this target, resolved once.

    The returned callable is invoked on every launch with the device index, so a
    caller that switches streams still launches on the stream current now.
    """
    global _RAW
    if _RAW is not None:
        return _RAW
    fn = None
    raw = None
    try:
        import torch_npu  # noqa: F401
        raw = getattr(torch_npu._C, "_npu_getCurrentRawStreamNoWait", None)
    except Exception:
        raw = None
    if raw is not None:
        try:
            if int(raw(0)) == int(torch.npu.current_stream().npu_stream):
                fn = raw
        except Exception:
            fn = None
    if fn is None:
        try:
            from triton.runtime import driver as _driver

            def fn(device=0):
                return _driver.active.get_current_stream(device)
        except Exception:
            def fn(device=0):
                return torch.npu.current_stream().npu_stream
    _RAW = fn
    return fn


def _resolve_stream(device):
    """Legacy per-device getter used by the generic dispatch path."""
    getter = _STREAM.get(device)
    if getter is not None:
        return getter
    raw = _raw_stream_fn()
    getter = lambda: raw(device)
    _STREAM[device] = getter
    return getter


def _early_ok():
    """The slim table is keyed by (dtype, numel) only, which is faithful on a
    single-device target; otherwise every call uses the device-keyed path."""
    global _EARLY_OK
    if _EARLY_OK is None:
        try:
            _EARLY_OK = int(torch.npu.device_count()) == 1
        except Exception:
            _EARLY_OK = False
    return _EARLY_OK


def _build_default(A, n):
    """Prebuilt launcher for the saturating-default request, or None.

    Two regimes, chosen by traffic:
      * tiny  (<= _SLIM_BYTES): device time hides under the launch floor, so the
        slim 2-runtime-argument kernel wins even where its tile is smaller.
      * large (> _SLIM_BYTES): device time dominates, so use the tile/kernel that
        measured fastest on the device with the ordinary argument list.
    """
    dtype = A.dtype
    limit = _DEFAULT_LIMITS.get(dtype)
    if limit is None:
        return None
    two_byte = dtype is not torch.float32
    small = n * A.element_size() <= _SLIM_BYTES
    try:
        getraw = _raw_stream_fn()
    except Exception:
        return None
    device = A.get_device()
    # (kernel, masked kernel, kind, tile cap, sequential tiles per program)
    #   kind 0: constants-baked slim kernel, 2 runtime arguments (host bound)
    #   kind 2: sequential loop with runtime bounds (device bound)
    cands = []
    if small:
        if two_byte:
            cands.append((_ntn_default, _ntn_default_masked, 0, _BLOCK_CLAMP_2B,
                          0))
            # bfloat16 needs ~1.8x the UB of fp16, so retry the slim kernel on a
            # tile the native clamp can still fit.
            cands.append((_ntn_default, _ntn_default_masked, 0, _BLOCK_STAGE, 0))
        cands.append((_ntn_stage_default, _ntn_stage_default_masked, 0,
                      _BLOCK_STAGE, 0))
    else:
        if two_byte:
            cands.append((_ntn_clamp_loop, _ntn_clamp_loop, 2, _BLOCK_CLAMP_2B, 2))
            if dtype is torch.bfloat16:
                # No native clamp for bfloat16, so try the native-dtype
                # compare/select on the larger tile before giving up on it.
                cands.append((_ntn_cs_loop, _ntn_cs_loop, 2, _BLOCK_CLAMP_2B, 2))
        cands.append((_ntn_stage_loop, _ntn_stage_loop, 2, _BLOCK_STAGE, 4))
    for kern, kmasked, kind, cap, want_iters in cands:
        if kind == 2:
            block = cap
            iters = want_iters if n >= want_iters * block else 1
            masked = True
        else:
            block = _pick_block(n, cap, _BLOCK_STAGE)
            iters = 0
            masked = bool(n % block)
        fn = kmasked if masked else kern
        try:
            if kind == 2:
                ck = fn.warmup(A, n, 0.0, 0.0, 0.0, ITERS=iters, BLOCK=block,
                               num_stages=1, grid=(1,))
            elif masked:
                ck = fn.warmup(A, n, 0.0, POS=limit, NEG=-limit, BLOCK=block,
                               grid=(1,))
            else:
                ck = fn.warmup(A, 0.0, POS=limit, NEG=-limit, BLOCK=block,
                               grid=(1,))
            runner = ck.run
            if getattr(runner, "compile_only", False) or getattr(
                    runner, "enable_msprof_register_tensor", False):
                continue
            md = runner.metadata
            if getattr(md, "debug_enabled", False) or getattr(md, "debug", False):
                continue
            launch, kfn, packed = runner.launch, ck.function, ck.packed_metadata
            lo, hi = limit, -limit
            if kind == 2:
                grid = -(-n // (iters * block))

                def fire(ptr, nan_v, _l=launch, _g=grid, _s=getraw, _d=device,
                         _f=kfn, _m=packed, _b=block, _lo=lo, _hi=hi,
                         _n=n, _it=iters):
                    _l(_g, 1, 1, _s(_d), _f, _m, None, None, None,
                       ptr, _n, nan_v, _lo, _hi, _it, _b)
            elif masked:
                grid = -(-n // block)

                def fire(ptr, nan_v, _l=launch, _g=grid, _s=getraw, _d=device,
                         _f=kfn, _m=packed, _b=block, _lo=lo, _hi=hi, _n=n):
                    _l(_g, 1, 1, _s(_d), _f, _m, None, None, None,
                       ptr, _n, nan_v, _lo, _hi, _b)
            else:
                grid = n // block

                def fire(ptr, nan_v, _l=launch, _g=grid, _s=getraw, _d=device,
                         _f=kfn, _m=packed, _b=block, _lo=lo, _hi=hi):
                    _l(_g, 1, 1, _s(_d), _f, _m, None, None, None,
                       ptr, nan_v, _lo, _hi, _b)
            return fire
        except Exception:
            continue
    return None


def _try_build(jitfn, A, n, block):
    """Resolve (launcher, function, metadata, grid, block, stream) or _FAIL."""
    grid = triton.cdiv(n, block)
    try:
        ck = jitfn.warmup(A, n, 0.0, 0.0, 0.0, BLOCK=block, grid=(1,))
        launcher = ck.run
        if getattr(launcher, "compile_only", False) or getattr(
                launcher, "enable_msprof_register_tensor", False):
            return _FAIL
        md = launcher.metadata
        if getattr(md, "debug_enabled", False) or getattr(md, "debug", False):
            return _FAIL
        return (launcher.launch, ck.function, ck.packed_metadata, grid, block,
                _resolve_stream(A.device.index or 0))
    except Exception:
        return _FAIL


def _build_entry(A, n, fast):
    """Generic (non-default) plan: native clamp tile then staged compare/select."""
    if fast:
        block = _pick_block(n, _BLOCK_CLAMP_2B, _BLOCK_STAGE)
        entry = _try_build(_nan_to_num_clamp_masked if n % block
                           else _nan_to_num_clamp, A, n, block)
        if entry is not _FAIL:
            return entry
    block = _pick_block(n, _BLOCK_STAGE, _BLOCK_STAGE)
    return _try_build(_nan_to_num_stage, A, n, block)


def _launch_strided(A, n, nan, posinf, neginf):
    shape = A.shape
    stride = A.stride()
    dims = []  # (size, stride), inner -> outer, adjacent dims merged when compact
    for d in range(len(shape) - 1, -1, -1):
        s = shape[d]
        if s == 1:
            continue
        st = stride[d]
        if dims and st == dims[-1][0] * dims[-1][1]:
            dims[-1] = (dims[-1][0] * s, dims[-1][1])
        else:
            dims.append((s, st))
    dims.reverse()
    if len(dims) <= 1:
        scale = dims[0][1] if dims else 1
        grid = (triton.cdiv(n, _BLOCK_STRIDED),)
        _nan_to_num_scaled[grid](A, n, nan, posinf, neginf,
                                 SCALE=scale, BLOCK=_BLOCK_STRIDED)
        return
    if len(dims) > _MAX_DIMS:
        # Extremely rare (>8 non-mergeable axes): peel the outer axis on the host.
        for i in range(A.shape[0]):
            sub = A.select(0, i)
            _dispatch(sub, sub.numel(), nan, posinf, neginf, False)
        return
    sizes = [d[0] for d in dims] + [1] * (_MAX_DIMS - len(dims))
    sts = [d[1] for d in dims] + [0] * (_MAX_DIMS - len(dims))
    grid = (triton.cdiv(n, _BLOCK_STRIDED),)
    _nan_to_num_nd[grid](A, n, nan, posinf, neginf, *sizes, *sts,
                         NDIM=len(dims), BLOCK=_BLOCK_STRIDED)


def _dispatch(A, n, nan, posinf, neginf, fast):
    if not A.is_contiguous():
        _launch_strided(A, n, nan, posinf, neginf)
        return
    key = (A.dtype, n, fast)
    entry = _ENTRIES.get(key)
    if entry is None:
        entry = _build_entry(A, n, fast)
        _ENTRIES[key] = entry
    if entry is not _FAIL:
        entry[0](entry[3], 1, 1, entry[5](), entry[1], entry[2],
                 None, None, None,
                 A.data_ptr(), n, nan, posinf, neginf, entry[4])
        return
    block = _pick_block(n, _BLOCK_STAGE, _BLOCK_STAGE)
    _nan_to_num_stage[(triton.cdiv(n, block),)](A, n, nan, posinf, neginf,
                                                BLOCK=block)


def _legacy_run(A, nan=None, posinf=None, neginf=None):
    if not A.is_floating_point():
        return A
    n = A.numel()
    if n == 0:
        return A
    finfo = _FINFO.get(A.dtype)
    if finfo is None:
        finfo = torch.finfo(A.dtype)
        _FINFO[A.dtype] = finfo
    default = posinf is None and neginf is None
    if default:
        fast = A.element_size() == 2
        posinf = finfo.max
        neginf = finfo.min
    else:
        if posinf is None:
            posinf = finfo.max
        if neginf is None:
            neginf = finfo.min
        fast = (A.element_size() == 2 and posinf >= finfo.max
                and neginf <= finfo.min)
    if nan is None:
        nan = 0.0
    if default and A.is_contiguous() and not (A.data_ptr() & 15) and _early_ok():
        fire = _build_default(A, n)
        if fire is not None:
            _EARLY.setdefault(A.dtype, {})[n] = fire
            fire(A.data_ptr(), nan)
            return A
    _dispatch(A, n, nan, posinf, neginf, fast)
    return A


def run(A, nan=None, posinf=None, neginf=None):
    if posinf is None and neginf is None:
        plans = _EARLY.get(A.dtype)
        if plans is not None:
            fire = plans.get(A.numel())
            if fire is not None:
                pointer = A.data_ptr()
                if not (pointer & 15) and A.is_contiguous():
                    fire(pointer, 0.0 if nan is None else nan)
                    return A
    return _legacy_run(A, nan, posinf, neginf)
