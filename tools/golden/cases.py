"""Per-op golden test cases.

The set of *ops* to check is never hardcoded here or anywhere in this
harness -- `compare.py` gets that list from `_C._aten_implemented()` at run
time, so it grows automatically as `rust/torch_c` implements more. What
*is* necessarily hand-written, per op, is which inputs to feed both sides:
`aten.full.default`, `aten.add.Tensor` and `aten.mm.default` take
different arguments and there is no generic way to invent valid calls for
an arbitrary aten op.

To keep that hand-written part from silently going stale as coverage grows,
`compare.py` treats "op is in `_aten_implemented()` but has no entry in
`CASE_BUILDERS`" as a hard failure rather than a skip -- see its
`_missing_case_builder` handling. Adding a new op to the shim without also
adding a case builder here will fail the harness, on purpose.

Every case's `expect` documents what the harness should see:

  "match"       -- both sides must succeed and agree on dtype, shape, and
                   value (within tolerance). This is the default and covers
                   the "do they compute the same answer" question.
  "both_error"  -- both sides are expected to refuse (e.g. mm on non-2D
                   input). Either exception is accepted; the point is that
                   neither one silently computes something.
  "c_error"     -- a documented capability gap: torch computes a result,
                   `_C` refuses. If this ever flips to both succeeding, the
                   case should be promoted to "match" and its real values
                   diffed. If `_C` starts succeeding with the *wrong*
                   answer instead, this will fail loudly.
  "torch_error" -- the mirror image: `_C` computes a result in a case where
                   even upstream torch's own CPU kernel refuses (e.g.
                   uint32 add). Not a shim bug -- torch simply has no
                   kernel -- but worth tracking explicitly rather than
                   silently excluding.

Below the three ops this harness started with (full/add/mm) are 16 more
CASE_BUILDERS entries pre-seeded for ops rust/torch_c is actively
implementing but has not landed yet -- see the longer note right before
`arange_default_cases` for which ops, why, and how `compare.py` keeps them
from failing the harness before they exist.
"""

from __future__ import annotations

import math
import platform
from dataclasses import dataclass
from typing import Any, Callable

import dtypes as dt
from build import pair_from_flat


@dataclass
class Case:
    name: str
    op: str
    run_torch: Callable[[], Any]
    run_c: Callable[[], Any]
    expect: str = "match"  # "match" | "both_error" | "c_error" | "torch_error"
    note: str = ""
    # Only consulted when expect == "match" and both sides succeeded.
    # None means "use the default dtype/shape/value pipeline in compare.py".
    # Set this instead for results that pipeline can't handle: a plain
    # Python bool (is_floating_point), uninitialized memory whose bytes are
    # meaningless (empty), or a random draw whose *sequence* can't be
    # matched across two independent RNG implementations even with a
    # matched seed (randint). Signature: (torch_result, c_result) ->
    # (ok, detail_message).
    value_check: Callable[[Any, Any], tuple[bool, str]] | None = None


# --- aten.full.default -------------------------------------------------

# (fill_value, expect, note) per dtype. Two entries are deliberately live
# regression traps for real bugs found while building this harness (see the
# final report): torch refuses on overflow, `_C` silently wraps/saturates
# instead of refusing. They are left as `expect="match"` -- NOT "c_error"
# -- specifically so the harness keeps failing on them until someone fixes
# rust/torch_c (out of scope for this change) rather than the gap being
# quietly filed away as "known and accepted".
_FULL_FILLS: dict[str, list[tuple[Any, str, str]]] = {
    "float64": [
        (0.0, "match", ""),
        (-12345.6789, "match", ""),
        (3.14159265358979, "match", ""),
        (1e10, "match", ""),
        (-1e10, "match", ""),
    ],
    "float32": [
        (0.0, "match", ""),
        (-12345.678, "match", ""),
        (3.1415927, "match", ""),
        (1e6, "match", ""),
        (-1e6, "match", ""),
    ],
    "float16": [
        (0.0, "match", ""),
        (-100.5, "match", ""),
        (65504.0, "match", "max finite float16"),
        (
            1e6,
            "match",
            "BUG (found by this harness): torch.ops.aten.full.default "
            "refuses fill values that overflow float16 "
            "(RuntimeError: value cannot be converted to type c10::Half "
            "without overflow); _C silently returns inf instead of "
            "refusing. Left as expect=match so the harness keeps failing "
            "until rust/torch_c is fixed.",
        ),
    ],
    "bfloat16": [
        (0.0, "match", ""),
        (-1000.0, "match", ""),
        (1e5, "match", ""),
        (-1e5, "match", ""),
    ],
    "int64": [
        (0, "match", ""),
        (-1234567890123, "match", ""),
        (10**12, "match", ""),
        (-(10**12), "match", ""),
    ],
    "int32": [
        (0, "match", ""),
        (-2147483648, "match", "int32 min"),
        (2147483647, "match", "int32 max"),
        (
            2147483648,
            "match",
            "BUG (found by this harness): torch.ops.aten.full.default "
            "refuses a fill value one past int32 max (RuntimeError: value "
            "cannot be converted to type int without overflow); _C "
            "silently wraps around to int32 min (two's-complement "
            "overflow) instead of refusing. Left as expect=match so the "
            "harness keeps failing until rust/torch_c is fixed.",
        ),
    ],
    "int16": [
        (0, "match", ""),
        (-32768, "match", ""),
        (32767, "match", ""),
    ],
    "uint8": [
        (0, "match", ""),
        (255, "match", "uint8 max"),
        (128, "match", ""),
        (-1, "match", "both sides wrap to 255 -- consistent modular wraparound"),
    ],
    "uint32": [
        (0, "match", ""),
        (4294967295, "match", "uint32 max"),
        (12345, "match", ""),
    ],
}

_FULL_SHAPES_SMALL: list[tuple[int, ...]] = [(), (3,), (2, 3)]
_FULL_SHAPES_EXTRA: list[tuple[int, ...]] = [(0, 3), (1, 4, 1), (50,)]


def _full_case(torch_module, c_module, torch_call, shape, fill, dtype_name, expect, note):
    shape_list = list(shape)

    if dtype_name is None:
        run_torch = lambda: torch_call(shape_list, fill)
        run_c = lambda: c_module._aten_dispatch("aten.full.default", shape_list, fill)
    else:
        t_dt = dt.torch_dtype(torch_module, dtype_name)
        c_dt = dt.c_dtype(c_module, dtype_name)
        run_torch = lambda: torch_call(shape_list, fill, dtype=t_dt)
        run_c = lambda: c_module._aten_dispatch(
            "aten.full.default", shape_list, fill, dtype=c_dt
        )

    name = f"full(shape={shape_list}, fill={fill!r}, dtype={dtype_name or 'inferred'})"
    return Case(
        name=name,
        op="aten.full.default",
        run_torch=run_torch,
        run_c=run_c,
        expect=expect,
        note=note,
    )


def full_cases(torch_module, c_module, torch_call) -> list[Case]:
    cases: list[Case] = []

    # Default dtype inference: torch.full infers int64 from a python int
    # fill value and float32 from a python float one (docs/TORCH_C.md §2).
    for fill, note in [
        (0, "default-dtype int fill -> expect int64"),
        (-7, "default-dtype int fill -> expect int64"),
        (3.5, "default-dtype float fill -> expect float32"),
        (-125000.25, "default-dtype float fill -> expect float32"),
    ]:
        for shape in _FULL_SHAPES_SMALL:
            cases.append(
                _full_case(torch_module, c_module, torch_call, shape, fill, None, "match", note)
            )

    for dtype_name in dt.DEFAULT_DTYPES:
        for fill, expect, note in _FULL_FILLS[dtype_name]:
            for shape in _FULL_SHAPES_SMALL:
                cases.append(
                    _full_case(
                        torch_module, c_module, torch_call, shape, fill, dtype_name, expect, note
                    )
                )

    for shape in _FULL_SHAPES_EXTRA:
        cases.append(
            _full_case(
                torch_module, c_module, torch_call, shape, 3.5, "float32", "match", "extra shape coverage"
            )
        )
        cases.append(
            _full_case(
                torch_module, c_module, torch_call, shape, 7, "int64", "match", "extra shape coverage"
            )
        )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # size/fill_value/dtype all by keyword, not just positionally.
    cases.append(
        Case(
            name="full(size=/fill_value=/dtype= all by keyword)",
            op="aten.full.default",
            run_torch=lambda: torch_call(size=[2, 2], fill_value=3.0, dtype=dt.torch_dtype(torch_module, "float32")),
            run_c=lambda: c_module._aten_dispatch(
                "aten.full.default", size=[2, 2], fill_value=3.0, dtype=dt.c_dtype(c_module, "float32")
            ),
        )
    )

    return cases


# --- aten.add.Tensor -----------------------------------------------------

_FLOAT_ADD_DTYPES = ["float64", "float32", "float16", "bfloat16"]


def _float_add_scenarios(big: float) -> list[dict]:
    return [
        dict(a_flat=[1.0, 2.0, 3.0, 4.0], a_shape=(2, 2), b_flat=[10.0, 20.0], b_shape=(1, 2), alpha=None, note="row-broadcast"),
        dict(a_flat=[1.0, 2.0, 3.0, 4.0], a_shape=(2, 2), b_flat=[10.0, 20.0], b_shape=(1, 2), alpha=2.0, note="row-broadcast, alpha=2"),
        dict(a_flat=[0.0, -5.0, big, -big], a_shape=(2, 2), b_flat=[0.0, 5.0, -big, big], b_shape=(2, 2), alpha=-1.5, note="boundary values (0/neg/large), alpha=-1.5"),
        dict(a_flat=[5.0], a_shape=(), b_flat=[1.0, 2.0, 3.0, 4.0], b_shape=(2, 2), alpha=None, note="scalar (0-d) broadcast"),
        dict(a_flat=[1.0] * 24, a_shape=(2, 3, 4), b_flat=[1.0, 2.0, 3.0, 4.0], b_shape=(4,), alpha=0.0, note="3D broadcast, alpha=0"),
        dict(a_flat=[1.0, 2.0, 3.0, 4.0, 5.0, 6.0], a_shape=(2, 3), b_flat=[10.0, 20.0], b_shape=(2, 1), alpha=None, note="column-broadcast"),
    ]


_FLOAT_ADD_MAGNITUDE = {"float64": 1e5, "float32": 1e5, "float16": 100.0, "bfloat16": 1e4}


def _int_add_scenarios_signed(big: int) -> list[dict]:
    return [
        dict(a_flat=[1, 2, 3, 4], a_shape=(2, 2), b_flat=[10, 20, 30, 40], b_shape=(2, 2), alpha=None, note="elementwise"),
        dict(a_flat=[1, 2, 3, 4], a_shape=(2, 2), b_flat=[10, 20, 30, 40], b_shape=(2, 2), alpha=3, note="elementwise, alpha=3"),
        dict(a_flat=[0, -5, big, -big], a_shape=(2, 2), b_flat=[0, 5, -big, big], b_shape=(2, 2), alpha=-1, note="boundary values (0/neg/large), alpha=-1"),
        dict(a_flat=[7], a_shape=(), b_flat=[1, 2, 3, 4], b_shape=(2, 2), alpha=None, note="scalar (0-d) broadcast"),
    ]


def _uint_add_scenarios(big: int) -> list[dict]:
    return [
        dict(a_flat=[1, 2, 3, 4], a_shape=(2, 2), b_flat=[10, 20, 30, 40], b_shape=(2, 2), alpha=None, note="elementwise"),
        dict(a_flat=[0, 1, big, big - 1], a_shape=(2, 2), b_flat=[0, 1, 0, 1], b_shape=(2, 2), alpha=1, note="boundary values (0/large), alpha=1"),
        dict(a_flat=[7], a_shape=(), b_flat=[1, 2, 3, 4], b_shape=(2, 2), alpha=None, note="scalar (0-d) broadcast"),
    ]


def _add_case(torch_module, c_module, torch_call, dtype_name, scenario) -> Case:
    a_t, a_c = pair_from_flat(torch_module, c_module, scenario["a_flat"], scenario["a_shape"], dtype_name)
    b_t, b_c = pair_from_flat(torch_module, c_module, scenario["b_flat"], scenario["b_shape"], dtype_name)
    alpha = scenario["alpha"]

    if alpha is None:
        run_torch = lambda: torch_call(a_t, b_t)
        run_c = lambda: c_module._aten_dispatch("aten.add.Tensor", a_c, b_c)
    else:
        run_torch = lambda: torch_call(a_t, b_t, alpha=alpha)
        run_c = lambda: c_module._aten_dispatch("aten.add.Tensor", a_c, b_c, alpha=alpha)

    name = f"add(dtype={dtype_name}, a_shape={scenario['a_shape']}, b_shape={scenario['b_shape']}, alpha={alpha}) [{scenario['note']}]"
    return Case(name=name, op="aten.add.Tensor", run_torch=run_torch, run_c=run_c)


def add_cases(torch_module, c_module, torch_call) -> list[Case]:
    cases: list[Case] = []

    for dtype_name in _FLOAT_ADD_DTYPES:
        for scenario in _float_add_scenarios(_FLOAT_ADD_MAGNITUDE[dtype_name]):
            cases.append(_add_case(torch_module, c_module, torch_call, dtype_name, scenario))

    for dtype_name, big in [("int64", 10**9), ("int32", 10**6), ("int16", 1000)]:
        for scenario in _int_add_scenarios_signed(big):
            cases.append(_add_case(torch_module, c_module, torch_call, dtype_name, scenario))

    for scenario in _uint_add_scenarios(200):
        cases.append(_add_case(torch_module, c_module, torch_call, "uint8", scenario))

    # Known gap: torch's own CPU kernel has no `add_stub` for UInt32, so
    # torch refuses while `_C` (via candle) computes fine. Not a shim bug.
    for scenario in _uint_add_scenarios(4_000_000_000):
        a_t, a_c = pair_from_flat(torch_module, c_module, scenario["a_flat"], scenario["a_shape"], "uint32")
        b_t, b_c = pair_from_flat(torch_module, c_module, scenario["b_flat"], scenario["b_shape"], "uint32")
        run_torch = lambda a_t=a_t, b_t=b_t: torch_call(a_t, b_t)
        run_c = lambda a_c=a_c, b_c=b_c: c_module._aten_dispatch("aten.add.Tensor", a_c, b_c)
        cases.append(
            Case(
                name=f"add(dtype=uint32, a_shape={scenario['a_shape']}, b_shape={scenario['b_shape']}) [{scenario['note']}]",
                op="aten.add.Tensor",
                run_torch=run_torch,
                run_c=run_c,
                expect="torch_error",
                note="torch has no CPU add kernel for uint32 (NotImplementedError: \"add_stub\" not implemented for 'UInt32'); _C computes it via candle. Not a shim bug -- torch is the one missing the kernel.",
            )
        )

    # Known gap, explicitly called out in docs/TORCH_C.md §2: dtype
    # promotion is refused rather than guessed.
    af_t, af_c = pair_from_flat(torch_module, c_module, [1.0], [1], "float32")
    bf_t, bf_c = pair_from_flat(torch_module, c_module, [1.0], [1], "float64")
    cases.append(
        Case(
            name="add(dtype-mismatch float32 vs float64)",
            op="aten.add.Tensor",
            run_torch=lambda: torch_call(af_t, bf_t),
            run_c=lambda: c_module._aten_dispatch("aten.add.Tensor", af_c, bf_c),
            expect="c_error",
            note="dtype promotion is deliberately unimplemented (docs/TORCH_C.md §2); torch promotes to float64, _C refuses rather than guess a promotion table.",
        )
    )

    cases.extend(_reduced_float_add_cases(torch_module, c_module, torch_call))

    # docs/DISPATCH.md §4.1: every case above calls the shim positionally, so
    # the keyword path through `_aten_dispatch` (what `bootstrap.py`'s
    # `dispatch(key, **bound)` actually sends in production) was never
    # exercised -- a tampered `interned_name` arm for "self"/"other"/"alpha"
    # passed this whole suite. This closes that for the busiest three names.
    kw_a_t, kw_a_c = pair_from_flat(torch_module, c_module, [1.0, 2.0, 3.0, 4.0], (2, 2), "float32")
    kw_b_t, kw_b_c = pair_from_flat(torch_module, c_module, [10.0, 20.0, 30.0, 40.0], (2, 2), "float32")
    cases.append(
        Case(
            name="add(dtype=float32, self=/other=/alpha= all by keyword)",
            op="aten.add.Tensor",
            run_torch=lambda: torch_call(self=kw_a_t, other=kw_b_t, alpha=2.0),
            run_c=lambda: c_module._aten_dispatch("aten.add.Tensor", self=kw_a_c, other=kw_b_c, alpha=2.0),
            note="keyword-argument coverage -- see the module note above and docs/GOLDEN.md",
        )
    )

    return cases


# --- reduced-float exact narrowing -----------------------------------------
#
# torch computes `bfloat16`/`float16` arithmetic in `at::opmath_type` (float
# for both) and narrows back **once**, with round-to-nearest-even. Getting
# that wrong costs exactly one ulp per element, which every tolerance in
# `tools/golden/dtypes.py` accepts -- so the cases below opt out of the
# tolerance pipeline entirely and demand bit-exact agreement.
#
# Two things made this a live gap rather than a hypothetical one, and both
# are why the cases look the way they do:
#
#   * **Size.** Every other case in this file is at most 24 elements. The
#     shim's `bfloat16` add narrowed correctly below 32 elements and
#     truncated at 32 and above (measured; docs/BF16.md §3), because the
#     wrong rule lived on a vectorised path nothing here was big enough to
#     reach. These probes are 64 and 256 elements on purpose.
#   * **Values.** Tidy constants round the same way under every rule --
#     0.5 + 0.25 cannot distinguish truncation from round-to-nearest. The
#     probe below is an LCG so that a useful fraction of the exact sums land
#     on or beside a narrowing boundary.
#
# The failure this guards against is not "slightly less accurate". A biased
# narrowing pushes every rounded element the same direction, so a residual
# stream accumulates it: docs/BF16.md measures it reaching an O(1) logit
# difference and different generated text after 30 layers.
_REDUCED_FLOAT_DTYPES = ["float16", "bfloat16"]


def _reduced_float_probe(n: int, seed: int, scale: float = 1.0) -> list[float]:
    out, state = [], seed
    for _ in range(n):
        state = (state * 1103515245 + 12345) % 2147483648
        out.append(round(((state / 2147483648.0) * 2.0 - 1.0) * scale, 6))
    return out


# --- the reduced-float scalar rule (docs/SCALAR.md) ------------------------
# When an op folds a Python number into a `float16`/`bfloat16` tensor, upstream
# reads that number at one of two precisions, and **which one is a property of
# the individual kernel, not of the op family**: `mul` reads it with
# `original_scalar_value<opmath_t>(2)` (so `bf16 * 0.3` multiplies by `0.3f`),
# `add` reads it through the iterator's common dtype (so `bf16 + 0.3` adds
# `0.30078125`). Neither is derivable from the other and both were measured.
#
# **A case set can only see the difference if it is built to.** Two conditions,
# and dropping either one makes every case pass under both rules:
#
#   * the **scalar** must not be representable in the tensor's dtype. `0.5`,
#     `2.0` and `-1.5` round to themselves in `float16` and `bfloat16`, so
#     narrowing them is the identity and the two implementations coincide. Every
#     scalar `mul_scalar_cases` had was of exactly that kind, which is why an
#     op that has been wrong for months passed every case it had.
#   * the **tensor values** must be representable, so that the only rounding
#     under test is the scalar's. Integers do that in both dtypes.
#
# The separating scalars below were picked by measuring, not by looking
# irregular -- `0.1` separates 4 of these 8 values in `float16` and only 1 in
# `bfloat16`, which is the same near-miss that let `div.Scalar` pass for months
# (docs/TRAIN.md §4: `bfloat16` rounds both roads of `1/0.3` to `3.328125`).
#
#   0.3   5/8 in bfloat16, 3/8 in float16   the value docs/TRAIN.md §5 measured
#   0.7   1/8 in bfloat16, 5/8 in float16   float16's separator, bfloat16's near miss
#   1.3   5/8 in bfloat16, 4/8 in float16   >1, so the product crosses a binade
#
# and `0.5`/`2.0` are carried as controls: they pass under either rule, and a
# run where *only* they pass is a run that has stopped testing anything.
_SCALAR_RULE_VALUES = [3.0, 5.0, 7.0, 11.0, 13.0, 96.0, -3.0, -5.0]
_SCALAR_RULE_SEPARATING = (0.3, 0.7, 1.3)
_SCALAR_RULE_CONTROLS = (0.5, 2.0)


def _scalar_rule_cases(
    torch_module,
    c_module,
    op,
    torch_of,
    c_of,
    *,
    rule: str,
    why: str,
    dtypes=_REDUCED_FLOAT_DTYPES,
    values=None,
    shape=None,
    separating=_SCALAR_RULE_SEPARATING,
    controls=_SCALAR_RULE_CONTROLS,
) -> list[Case]:
    """Cases that separate "the scalar is narrowed into the tensor's dtype"
    from "the scalar is widened to `opmath_type`", for one op.

    `rule` is upstream's measured answer for this kernel -- `"widen"` or
    `"narrow"` -- and goes in the case note so that a later reader can tell a
    deliberate asymmetry from an oversight. `why` names the line of upstream
    that decides it.

    `_exact_value_check`, never the default pipeline: the whole difference is
    one representable step, and `bfloat16`'s tolerance here is `6e-2`.
    """
    flat = list(values if values is not None else _SCALAR_RULE_VALUES)
    dims = tuple(shape if shape is not None else (len(flat),))
    cases: list[Case] = []
    for dtype_name in dtypes:
        for scalar in list(separating) + list(controls):
            control = scalar in controls
            a_t, a_c = pair_from_flat(torch_module, c_module, flat, dims, dtype_name)
            cases.append(
                Case(
                    name=f"{op}(dtype={dtype_name}, scalar={scalar!r}) "
                         f"[scalar rule: {rule}{'; CONTROL' if control else ''}]",
                    op=op,
                    run_torch=lambda a_t=a_t, s=scalar: torch_of(a_t, s),
                    run_c=lambda a_c=a_c, s=scalar: c_of(a_c, s),
                    value_check=_exact_value_check,
                    note=(
                        f"upstream {rule}s the scalar here ({why}). "
                        + (
                            f"{scalar!r} IS representable in {dtype_name}, so this case "
                            "passes under either rule -- it is the control that shows the "
                            "others are doing work"
                            if control
                            else f"{scalar!r} is not representable in {dtype_name}, so the "
                                 "two rules give different bits"
                        )
                    ),
                )
            )
    return cases


def _exact_value_check(t_res, c_res) -> tuple[bool, str]:
    """dtype, shape, and every value bit-for-bit -- no tolerance.

    Reduced-float values are exactly representable as Python floats, so
    equality here really is bitwise and not an accident of formatting.
    """
    t_dtype, c_dtype = dt.dtype_name(t_res.dtype), dt.dtype_name(c_res.dtype)
    if t_dtype != c_dtype:
        return False, f"dtype mismatch: torch={t_dtype} c={c_dtype}"
    t_shape = tuple(int(x) for x in t_res.shape)
    c_shape = tuple(int(x) for x in c_res.shape)
    if t_shape != c_shape:
        return False, f"shape mismatch: torch={t_shape} c={c_shape}"
    t_vals = _flatten_values(t_res.tolist())
    c_vals = _flatten_values(c_res.tolist())
    wrong = [i for i, (t, c) in enumerate(zip(t_vals, c_vals)) if t != c]
    if wrong:
        i = wrong[0]
        return False, (
            f"not bit-exact: {len(wrong)}/{len(t_vals)} elements differ, first "
            f"at index {i} (torch={t_vals[i]!r} c={c_vals[i]!r}); reduced-float "
            f"arithmetic must narrow once, round-to-nearest-even"
        )
    return True, f"dtype={t_dtype} shape={t_shape}, all {len(t_vals)} values bit-exact"


def _reduced_float_add_cases(torch_module, c_module, torch_call) -> list[Case]:
    cases: list[Case] = []
    for dtype_name in _REDUCED_FLOAT_DTYPES:
        a64 = _reduced_float_probe(64, 20260828)
        b64 = _reduced_float_probe(64, 7654321, scale=0.03125)
        for shape, alpha, note in [
            ((64,), None, "64 elements -- above the vectorised-path threshold"),
            ((8, 8), None, "64 elements, 2-D"),
            ((64,), 3.0, "64 elements, alpha=3 (alpha is applied in opmath too)"),
        ]:
            a_t, a_c = pair_from_flat(torch_module, c_module, a64, shape, dtype_name)
            b_t, b_c = pair_from_flat(torch_module, c_module, b64, shape, dtype_name)
            if alpha is None:
                run_torch = lambda a_t=a_t, b_t=b_t: torch_call(a_t, b_t)
                run_c = lambda a_c=a_c, b_c=b_c: c_module._aten_dispatch("aten.add.Tensor", a_c, b_c)
            else:
                run_torch = lambda a_t=a_t, b_t=b_t, al=alpha: torch_call(a_t, b_t, alpha=al)
                run_c = lambda a_c=a_c, b_c=b_c, al=alpha: c_module._aten_dispatch(
                    "aten.add.Tensor", a_c, b_c, alpha=al
                )
            cases.append(
                Case(
                    name=f"add(dtype={dtype_name}, shape={shape}, alpha={alpha}) [exact narrowing: {note}]",
                    op="aten.add.Tensor",
                    run_torch=run_torch,
                    run_c=run_c,
                    value_check=_exact_value_check,
                    note="bit-exact, no tolerance -- see the section note above",
                )
            )
        # Broadcast, because rotary embedding's add really is broadcast over
        # the head axis and that is one of the two adds this bug corrupted.
        a_t, a_c = pair_from_flat(
            torch_module, c_module, _reduced_float_probe(128, 4242), (2, 64), dtype_name
        )
        b_t, b_c = pair_from_flat(
            torch_module, c_module, _reduced_float_probe(64, 99, scale=0.03125), (1, 64), dtype_name
        )
        cases.append(
            Case(
                name=f"add(dtype={dtype_name}, shape=(2, 64) + (1, 64)) [exact narrowing: broadcast]",
                op="aten.add.Tensor",
                run_torch=lambda a_t=a_t, b_t=b_t: torch_call(a_t, b_t),
                run_c=lambda a_c=a_c, b_c=b_c: c_module._aten_dispatch("aten.add.Tensor", a_c, b_c),
                value_check=_exact_value_check,
                note="bit-exact, no tolerance -- see the section note above",
            )
        )
    return cases


def _reduced_float_reduce_cases(torch_module, c_module, op, torch_call) -> list[Case]:
    """`sum`/`mean` accumulate in `acc_type<T>` -- float for both reduced
    floats -- and narrow once. `cumsum_default` already states this rule in
    its own doc comment; these check that the other two reductions obey it,
    over a row long enough for the accumulator width to matter."""
    cases: list[Case] = []
    label = op.split(".")[1]
    for dtype_name in _REDUCED_FLOAT_DTYPES:
        a_t, a_c = pair_from_flat(
            torch_module, c_module, _reduced_float_probe(256, 31337), (4, 64), dtype_name
        )
        for dim, keepdim in [([1], False), ([1], True), ([0], False)]:
            cases.append(
                Case(
                    name=f"{label}(dtype={dtype_name}, shape=(4, 64), dim={dim}, keepdim={keepdim}) [exact narrowing]",
                    op=op,
                    run_torch=lambda a_t=a_t, d=dim, k=keepdim: torch_call(a_t, d, k),
                    run_c=lambda a_c=a_c, d=dim, k=keepdim: c_module._aten_dispatch(op, a_c, d, k),
                    value_check=_exact_value_check,
                    note="bit-exact, no tolerance -- reductions accumulate in float and narrow once",
                )
            )
    return cases


# --- aten.mm.default -------------------------------------------------------

# `bfloat16` moved from the gap list to the match list when `mm`/`bmm`/`addmm`
# started accumulating reduced-precision GEMMs in float32, which is what torch
# does (`at::opmath_type`, measured bitwise -- see `gemm_accumulate_in` in
# rust/torch_c/src/aten.rs). candle still has no BF16 matmul kernel; the point
# is that it is never asked for one, because upstream does not ask for one
# either. The integral dtypes stay: that gap is real, and float32 cannot stand
# in for an int64 product.
_MM_MATCH_DTYPES = ["float32", "float64", "float16", "bfloat16"]
_MM_C_ERROR_DTYPES = ["int64", "int32", "int16", "uint8"]


def _mm_case(torch_module, c_module, torch_call, dtype_name, a_flat, a_shape, b_flat, b_shape, expect="match", note=""):
    a_t, a_c = pair_from_flat(torch_module, c_module, a_flat, a_shape, dtype_name)
    b_t, b_c = pair_from_flat(torch_module, c_module, b_flat, b_shape, dtype_name)
    name = f"mm(dtype={dtype_name}, a_shape={a_shape}, b_shape={b_shape}) [{note or 'plain'}]"
    return Case(
        name=name,
        op="aten.mm.default",
        run_torch=lambda: torch_call(a_t, b_t),
        run_c=lambda: c_module._aten_dispatch("aten.mm.default", a_c, b_c),
        expect=expect,
        note=note,
    )


def mm_cases(torch_module, c_module, torch_call) -> list[Case]:
    cases: list[Case] = []

    for dtype_name in _MM_MATCH_DTYPES:
        big = 50.0 if dtype_name == "float16" else 1000.0
        square = [1.0, 2.0, 3.0, 4.0]
        square_b = [5.0, 6.0, 7.0, 8.0]  # torch.mm([[1,2],[3,4]],[[5,6],[7,8]]) == [[19,22],[43,50]]
        cases.append(_mm_case(torch_module, c_module, torch_call, dtype_name, square, (2, 2), square_b, (2, 2), note="known 2x2 answer"))

        rect_a = [1.0, 2.0, 3.0, 4.0, 5.0, 6.0]
        rect_b = [1.0, 2.0, 3.0, 4.0, 5.0, 6.0, 7.0, 8.0]
        cases.append(_mm_case(torch_module, c_module, torch_call, dtype_name, rect_a, (3, 2), rect_b, (2, 4), note="rectangular"))

        dot_a = [1.0, 2.0, 3.0, 4.0, 5.0]
        dot_b = [1.0, 2.0, 3.0, 4.0, 5.0]
        cases.append(_mm_case(torch_module, c_module, torch_call, dtype_name, dot_a, (1, 5), dot_b, (5, 1), note="row-vector . column-vector (dot product)"))

        boundary_a = [0.0, -1.0, big, -big, 2.0, -2.0, 0.0, 5.0, 1.0, 1.0, 1.0, 1.0, -5.0, 5.0, -5.0, 5.0]
        identity_4x4 = [1.0, 0.0, 0.0, 0.0, 0.0, 1.0, 0.0, 0.0, 0.0, 0.0, 1.0, 0.0, 0.0, 0.0, 0.0, 1.0]
        cases.append(
            _mm_case(
                torch_module,
                c_module,
                torch_call,
                dtype_name,
                boundary_a,
                (4, 4),
                identity_4x4,
                (4, 4),
                note="boundary values (0/neg/large) x identity",
            )
        )

    # Known gaps: candle's matmul kernel does not support these dtypes at
    # all (RuntimeError: "candle: unsupported dtype <X> for op matmul"),
    # while torch's CPU addmm does.
    for dtype_name in _MM_C_ERROR_DTYPES:
        a_flat = [1, 2, 3, 4] if dtype_name != "uint8" else [1, 2, 3, 4]
        b_flat = [1, 0, 0, 1]
        cases.append(
            _mm_case(
                torch_module,
                c_module,
                torch_call,
                dtype_name,
                a_flat,
                (2, 2),
                b_flat,
                (2, 2),
                expect="c_error",
                note=f"candle's matmul has no kernel for {dtype_name}; torch's CPU addmm does. See docs/TORCH_C.md §2 for int64 specifically -- int32/int16/uint8/bfloat16 have the same gap, found while building this harness.",
            )
        )

    # Both refuse: torch's own addmm has no UInt32 kernel either, and
    # candle refuses it too (for an unrelated reason). Either way, neither
    # side should silently produce a value.
    cases.append(
        _mm_case(
            torch_module,
            c_module,
            torch_call,
            "uint32",
            [1, 2, 3, 4],
            (2, 2),
            [1, 0, 0, 1],
            (2, 2),
            expect="both_error",
            note="torch: NotImplementedError (\"addmm_impl_cpu_\" not implemented for 'UInt32'); _C: candle has no matmul kernel for U32 either.",
        )
    )

    # mm must reject non-2D input on both sides -- candle's matmul batches,
    # torch.mm does not, and the shim explicitly guards against silently
    # standing in for bmm/matmul (docs/TORCH_C.md §2).
    a3_t, a3_c = pair_from_flat(torch_module, c_module, [1.0] * 8, (2, 2, 2), "float32")
    cases.append(
        Case(
            name="mm(3D input rejected on both sides)",
            op="aten.mm.default",
            run_torch=lambda: torch_call(a3_t, a3_t),
            run_c=lambda: c_module._aten_dispatch("aten.mm.default", a3_c, a3_c),
            expect="both_error",
            note="mm must not silently fall back to a batched matmul.",
        )
    )

    # Model-scale reduction depths -- the docs/GPT2.md §7 gap. See the long
    # note above `_gemm_scale_check`.
    for dtype_name, m, k, n, note in [
        ("float32", 8, 512, 8, "GPT-2 small's per-head depth, narrow output"),
        ("float32", 8, 1024, 8, "the first depth at which the shim and torch stop agreeing bitwise"),
        ("float32", 64, 1024, 64, "4096 outputs at depth 1024"),
        ("float64", 8, 1024, 8, "float64 at the same depth, for contrast"),
        ("float16", 8, 512, 8, "float16 at depth 512 -- the accumulation-dtype question"),
        ("bfloat16", 8, 512, 8, "bfloat16, which only has a matmul at all because of that"),
    ]:
        cases.append(
            _big_gemm_case(torch_module, c_module, torch_call, "aten.mm.default",
                           dtype_name, m, k, n, note=note)
        )

    return cases


# --- aten.matmul.default ------------------------------------------------------
#
# Landed in `_aten_implemented()` from `IMPLEMENTED_AWAITING_GOLDEN` alongside
# this builder. docs/LINEAR.md's layout-fallback fix (`gemm_with_layout_fallback`,
# skip the unconditional `.contiguous()` and copy only when candle refuses the
# layout) and its N-D x 2-D fold (`batched_matmul`: stack the batch into rows
# and run one 2-D GEMM instead of broadcasting the 2-D operand up to the
# batch, which is what candle's own `broadcast_matmul` otherwise does) both
# live inside this kernel, and it was the single most bit-changed kernel in
# that change -- 48 of 507 bitprobe cases moved, 35 of those newly agreeing
# with upstream torch, 0 regressed away from it -- while sitting in
# `IMPLEMENTED_AWAITING_GOLDEN`, where the 2760-case golden suite never ran
# it at all (docs/LINEAR.md §4.3).
#
# The cases below are picked to land on exactly the axes docs/LINEAR.md names
# as touched:
#   * rank combinations -- the fold only fires when the right operand is 2-D
#     and the left has more dimensions; every other combination still goes
#     through `broadcast_matmul`, so both branches need cases.
#   * a transposed-view operand (`t(weight)`) -- the literal shape
#     `bootstrap.py::linear` hands the kernel for every one of the 211
#     `F.linear` calls in one SmolLM2-135M forward pass (docs/LINEAR.md §1).
#   * a non-transpose strided operand and a swapped-batch-axis 4-D operand --
#     both are layouts Accelerate's `MatMul` refuses outright
#     (`MatMulUnexpectedStriding`/`ab_skip`, docs/LINEAR.md §2) and only reach
#     a correct answer through the copy-on-refusal fallback.
#   * broadcasting batch dimensions -- the shape `bmm_cases` above proves
#     `bmm` itself must refuse, but `matmul`'s own kernel (`broadcast_matmul`)
#     is exactly what has to compute it.
#
# The dtype split is `mm`'s, for `mm`'s reason: the multiply is candle's
# `matmul`, which has no integral or (unwidened) bf16/f16 kernel of its own.
#
# **Why the fold/transpose/strided/batch-swap cases below use `_gemm_lcg`
# noise instead of `list(range(...))`, and `_exact_value_check` instead of
# the default tolerance pipeline.** Measured directly (deleting the fold
# branch and, separately, forcing `gemm_with_layout_fallback` to copy
# unconditionally, then re-running against real upstream torch): with
# `list(range(...))`-style small-integer data, sums of exact integers round
# to the same bits regardless of which order candle adds them in, so a fold
# vs. broadcast (or copy vs. no-copy) difference is invisible no matter the
# shape -- confirmed up to real model scale (`(1,6,576) x t((49152,576))`,
# the literal `lm_head` call). With noisy `_gemm_lcg` floats it reappears,
# but **only below a reduction-depth threshold measured between k=256 and
# k=300 on this host** (Apple M1, Accelerate) -- above that, Accelerate's
# `sgemm` apparently converges on the same blocked summation order
# regardless of how the call arrived, and below it, it does not. Every case
# below that needs to catch a fold/layout regression therefore uses `k` at
# or under the toy shapes already in this file (k=3-4), which is deliberately
# smaller than `_matmul_model_case`'s k=512 rows -- those stay on
# `_gemm_scale_check`'s tolerance-bound because a real implementation is not
# expected to be bit-exact with upstream at that depth (`mm_cases`' own
# model-scale rows document the same k=1024 boundary). And the difference
# this produces is 1-2 ULP (~1e-7 on float32 magnitude-1 values), well under
# the default pipeline's `rtol=1e-5` -- so `_exact_value_check` is not
# decoration here, it is the only comparator that can see it.
_MATMUL_MATCH_DTYPES = _MM_MATCH_DTYPES
_MATMUL_C_ERROR_DTYPES = _MM_C_ERROR_DTYPES


def _matmul_case(torch_module, c_module, torch_call, dtype_name, a_flat, a_shape, b_flat, b_shape, expect="match", note="", value_check=None):
    a_t, a_c = pair_from_flat(torch_module, c_module, a_flat, a_shape, dtype_name)
    b_t, b_c = pair_from_flat(torch_module, c_module, b_flat, b_shape, dtype_name)
    name = f"matmul(dtype={dtype_name}, a_shape={a_shape}, b_shape={b_shape}) [{note or 'plain'}]"
    return Case(
        name=name,
        op="aten.matmul.default",
        run_torch=lambda: torch_call(a_t, b_t),
        run_c=lambda: c_module._aten_dispatch("aten.matmul.default", a_c, b_c),
        expect=expect,
        note=note,
        value_check=value_check,
    )


def _matmul_transposed_rhs_case(torch_module, c_module, torch_call, dtype_name, a_flat, a_shape, w_flat, w_shape, note="", value_check=None):
    """The right operand fed in as `t(...)` -- exactly the view
    `bootstrap.py::linear`'s `_t(weight)` produces (`aten.t.default`, never
    materialised) before handing it to this op. `w_shape` names the shape
    *before* the transpose; the case multiplies against its transpose."""
    op = "aten.matmul.default"
    a_t, a_c = pair_from_flat(torch_module, c_module, a_flat, a_shape, dtype_name)
    wbase_t, wbase_c = pair_from_flat(torch_module, c_module, w_flat, w_shape, dtype_name)
    w_t = wbase_t.t()
    w_c = c_module._aten_dispatch("aten.t.default", wbase_c)
    out_w_shape = (w_shape[1], w_shape[0])
    return Case(
        name=f"matmul(dtype={dtype_name}, a_shape={a_shape}, w_shape={w_shape} transposed view -> {out_w_shape}) [{note}]",
        op=op,
        run_torch=lambda: torch_call(a_t, w_t),
        run_c=lambda: c_module._aten_dispatch(op, a_c, w_c),
        note=note,
        value_check=value_check,
    )


def _matmul_transposed_lhs_case(torch_module, c_module, torch_call, dtype_name, a_flat, a_shape, w_flat, w_shape, note="", value_check=None):
    """The mirror image of `_matmul_transposed_rhs_case`: the *left* operand
    is the transposed view. `bootstrap.py::linear` never produces this shape,
    but `gemm_with_layout_fallback` treats both operands identically, so it
    is worth one direct check rather than trusting symmetry."""
    op = "aten.matmul.default"
    abase_t, abase_c = pair_from_flat(torch_module, c_module, a_flat, a_shape, dtype_name)
    w_t, w_c = pair_from_flat(torch_module, c_module, w_flat, w_shape, dtype_name)
    a_t = abase_t.t()
    a_c = c_module._aten_dispatch("aten.t.default", abase_c)
    out_a_shape = (a_shape[1], a_shape[0])
    return Case(
        name=f"matmul(dtype={dtype_name}, a_shape={a_shape} transposed view -> {out_a_shape}, w_shape={w_shape}) [{note}]",
        op=op,
        run_torch=lambda: torch_call(a_t, w_t),
        run_c=lambda: c_module._aten_dispatch(op, a_c, w_c),
        note=note,
        value_check=value_check,
    )


def _matmul_model_case(torch_module, c_module, torch_call, dtype_name, batch, m, k, n, transpose_w, note):
    """Model-scale, checked against the scale-aware GEMM bound (`_gemm_scale_check`)
    rather than a flat tolerance -- see the long note above it. `transpose_w`
    reproduces the exact `(activation 3-D) x t(weight)` shape `F.linear` passes."""
    op = "aten.matmul.default"
    a_flat = _gemm_lcg(batch * m * k, 101)
    a_shape = (batch, m, k)
    a_t, a_c = pair_from_flat(torch_module, c_module, a_flat, a_shape, dtype_name)
    if transpose_w:
        w_flat = _gemm_lcg(n * k, 102)
        wbase_t, wbase_c = pair_from_flat(torch_module, c_module, w_flat, (n, k), dtype_name)
        w_t = wbase_t.t()
        w_c = c_module._aten_dispatch("aten.t.default", wbase_c)
        w_note = f"({n},{k}) transposed view -> ({k},{n})"
    else:
        w_flat = _gemm_lcg(k * n, 102)
        w_t, w_c = pair_from_flat(torch_module, c_module, w_flat, (k, n), dtype_name)
        w_note = f"({k},{n})"
    return Case(
        name=f"matmul(dtype={dtype_name}, {a_shape}x{w_note}) [model-scale, k={k}: {note}]",
        op=op,
        run_torch=lambda: torch_call(a_t, w_t),
        run_c=lambda: c_module._aten_dispatch(op, a_c, w_c),
        note=note,
        value_check=_gemm_scale_check(dtype_name, k),
    )


def matmul_cases(torch_module, c_module, torch_call) -> list[Case]:
    cases: list[Case] = []

    # -- rank combinations. Only "left rank > 2, right rank == 2" folds
    # (`batched_matmul`'s first branch); everything else, including left
    # rank == right rank == 2, goes through `gemm_with_layout_fallback` +
    # candle's `broadcast_matmul`. Both branches get the full dtype sweep on
    # at least one shape apiece.
    square = [1.0, 2.0, 3.0, 4.0]
    square_b = [5.0, 6.0, 7.0, 8.0]  # torch.mm([[1,2],[3,4]],[[5,6],[7,8]]) == [[19,22],[43,50]]
    for dtype_name in _MATMUL_MATCH_DTYPES:
        cases.append(
            _matmul_case(torch_module, c_module, torch_call, dtype_name,
                        square, (2, 2), square_b, (2, 2),
                        note="2D x 2D -- rank equal, NOT the fold branch, known 2x2 answer")
        )

    # Noisy (not small-integer) data and a bit-exact check -- see the long
    # note above `_MATMUL_MATCH_DTYPES` on why: at this depth (k=4), folding
    # the batch into rows and running one GEMM is not always bit-identical to
    # candle's own broadcast-and-batch path, and only noise plus an exact
    # comparator can see that.
    fold_a, fold_a_shape = _gemm_lcg(24, 11), (2, 3, 4)
    fold_w, fold_w_shape = _gemm_lcg(20, 12), (4, 5)
    for dtype_name in _MATMUL_MATCH_DTYPES:
        cases.append(
            _matmul_case(torch_module, c_module, torch_call, dtype_name,
                        fold_a, fold_a_shape, fold_w, fold_w_shape,
                        note="3D x 2D, batch=2 -- the fold branch (batched_matmul's first arm)",
                        value_check=_exact_value_check)
        )

    # batch=1 is the literal shape every one of the 211 `F.linear` calls in a
    # SmolLM2-135M forward pass takes (docs/LINEAR.md §1's table) -- the fold
    # branch still fires (rank 3 > rank 2), but this is worth its own case
    # because a kernel that special-cased "batch of one" differently from
    # "batch of several" would only be caught here.
    b1_a, b1_a_shape = _gemm_lcg(24, 13), (1, 6, 4)
    for dtype_name in _MATMUL_MATCH_DTYPES:
        cases.append(
            _matmul_case(torch_module, c_module, torch_call, dtype_name,
                        b1_a, b1_a_shape, fold_w, fold_w_shape,
                        note="3D x 2D, batch=1 -- F.linear's own activation rank, still folds",
                        value_check=_exact_value_check)
        )

    batch3_a, batch3_a_shape = list(range(24)), (2, 3, 4)
    batch3_b, batch3_b_shape = list(range(40)), (2, 4, 5)
    for dtype_name in _MATMUL_MATCH_DTYPES:
        cases.append(
            _matmul_case(torch_module, c_module, torch_call, dtype_name,
                        batch3_a, batch3_a_shape, batch3_b, batch3_b_shape,
                        note="3D x 3D, matching batch -- broadcast_matmul, not the fold")
        )

    # Broadcasting batch dimensions -- `broadcast_matmul` must do this even
    # though `bmm_cases` proves `aten.bmm.default` must refuse the identical
    # shapes (its own "batch 1 x batch 2" case above).
    cases.append(
        _matmul_case(torch_module, c_module, torch_call, "float32",
                    list(range(12)), (1, 3, 4), batch3_b, batch3_b_shape,
                    note="3D x 3D, batch broadcasts 1 -> 2 -- broadcast_matmul's own job, "
                         "the shape bmm_cases proves bmm must refuse")
    )

    # Rank 4, both branches. The fold row reuses the noisy/exact treatment
    # above -- it is the same fold branch, one rank higher.
    cases.append(
        _matmul_case(torch_module, c_module, torch_call, "float32",
                    _gemm_lcg(48, 14), (2, 2, 3, 4), fold_w, fold_w_shape,
                    note="4D x 2D -- the fold branch at rank 4",
                    value_check=_exact_value_check)
    )
    cases.append(
        _matmul_case(torch_module, c_module, torch_call, "float32",
                    list(range(48)), (2, 2, 3, 4), batch3_b, batch3_b_shape,
                    note="4D x 3D -- broadcast_matmul broadcasts the (2,) batch3 leading dim "
                         "against 4D's leading (2,2)")
    )
    cases.append(
        _matmul_case(torch_module, c_module, torch_call, "float32",
                    list(range(48)), (2, 2, 3, 4), list(range(80)), (2, 2, 4, 5),
                    note="4D x 4D, matching batch")
    )

    # -- a transposed-view operand, dtype-swept -- the actual `F.linear`
    # shape, and the case docs/LINEAR.md's fold-rule change is really about.
    # Noisy data + `_exact_value_check` again (see the note above
    # `_MATMUL_MATCH_DTYPES`): this is the strongest of the fold/layout
    # cases, since it exercises the fold branch *and* a non-contiguous
    # operand together. bf16/f16 are included on purpose even though
    # docs/LINEAR.md §4.1 measured that the layout fallback is a no-op for
    # them (`opmath_in`'s widening to float32 already materialises a
    # contiguous tensor, so the transposed view never survives to
    # `gemm_with_layout_fallback`) -- that is a claim this suite should
    # stand behind with a passing case, not just a doc comment.
    tw_base, tw_base_shape = _gemm_lcg(20, 15), (5, 4)  # transposes to (4, 5)
    for dtype_name in _MATMUL_MATCH_DTYPES:
        cases.append(
            _matmul_transposed_rhs_case(torch_module, c_module, torch_call, dtype_name,
                                        b1_a, b1_a_shape, tw_base, tw_base_shape,
                                        note="rhs = t(weight), batch=1 activation -- F.linear's exact shape",
                                        value_check=_exact_value_check)
        )
        cases.append(
            _matmul_transposed_rhs_case(torch_module, c_module, torch_call, dtype_name,
                                        _gemm_lcg(72, 16), (3, 6, 4), tw_base, tw_base_shape,
                                        note="rhs = t(weight), batch=3 activation",
                                        value_check=_exact_value_check)
        )
    cases.append(
        _matmul_transposed_lhs_case(torch_module, c_module, torch_call, "float32",
                                    _gemm_lcg(12, 17), (4, 3), fold_w, fold_w_shape,
                                    note="lhs is the transposed view instead -- gemm_with_layout_fallback "
                                         "treats both operands the same, checked directly rather than "
                                         "assumed symmetric",
                                    value_check=_exact_value_check)
    )

    # -- a genuinely strided (non-transpose) operand: a column-strided slice,
    # which Accelerate's MatMul refuses outright (MatMulUnexpectedStriding,
    # docs/LINEAR.md §2) and only a correct answer comes back through the
    # copy-on-refusal fallback in `gemm_with_layout_fallback`. Noisy data +
    # exact check, same reasoning.
    strided_base_t, strided_base_c = pair_from_flat(torch_module, c_module, _gemm_lcg(64, 18), (4, 16), "float32")
    strided_t = strided_base_t[:, ::2]
    strided_c = c_module._aten_dispatch("aten.slice.Tensor", strided_base_c, 1, 0, 16, 2)
    sw_t, sw_c = pair_from_flat(torch_module, c_module, _gemm_lcg(40, 19), (8, 5), "float32")
    cases.append(
        Case(
            name="matmul(dtype=float32, a_shape=(4,16) sliced [:, ::2] -> (4,8) strided, w_shape=(8,5))",
            op="aten.matmul.default",
            run_torch=lambda: torch_call(strided_t, sw_t),
            run_c=lambda: c_module._aten_dispatch("aten.matmul.default", strided_c, sw_c),
            note="a non-transpose strided operand -- Accelerate's MatMul refuses this layout "
                 "outright; only the copy-on-refusal fallback answers correctly",
            value_check=_exact_value_check,
        )
    )

    # -- a swapped-batch-axis 4-D operand: candle's shared `MatMul::ab_skip`
    # needs the batch strides in one of four recognised shapes and refuses a
    # swapped pair, reachable only at rank 4+ (docs/LINEAR.md §2). Noisy
    # data + exact check, same reasoning.
    swap_base_t, swap_base_c = pair_from_flat(torch_module, c_module, _gemm_lcg(120, 20), (2, 3, 4, 5), "float32")
    swap_t = swap_base_t.transpose(0, 1)
    swap_c = c_module._aten_dispatch("aten.transpose.int", swap_base_c, 0, 1)
    swap_rhs_t, swap_rhs_c = pair_from_flat(torch_module, c_module, _gemm_lcg(180, 21), (3, 2, 5, 6), "float32")
    cases.append(
        Case(
            name="matmul(dtype=float32, a_shape=(2,3,4,5) transpose(0,1) -> (3,2,4,5) swapped-batch-axis, w_shape=(3,2,5,6))",
            op="aten.matmul.default",
            run_torch=lambda: torch_call(swap_t, swap_rhs_t),
            run_c=lambda: c_module._aten_dispatch("aten.matmul.default", swap_c, swap_rhs_c),
            note="swapped batch axes at rank 4 -- ab_skip refuses this batch stride shape "
                 "outright; only the copy-on-refusal fallback answers correctly",
            value_check=_exact_value_check,
        )
    )

    # -- the inherited candle gap: no matmul kernel for the integral dtypes,
    # exactly as aten.mm.default/aten.bmm.default/aten.addmm.default already
    # record.
    for dtype_name in _MATMUL_C_ERROR_DTYPES:
        cases.append(
            _matmul_case(torch_module, c_module, torch_call, dtype_name,
                        [1, 2, 3, 4], (2, 2), [1, 0, 0, 1], (2, 2), expect="c_error",
                        note=f"candle's matmul has no kernel for {dtype_name}; torch's CPU matmul does. "
                             "Same gap aten.mm.default already carries.")
        )
    cases.append(
        _matmul_case(torch_module, c_module, torch_call, "uint32",
                    [1, 2, 3, 4], (2, 2), [1, 0, 0, 1], (2, 2), expect="both_error",
                    note="torch: NotImplementedError (\"addmm_impl_cpu_\" not implemented for 'UInt32'); "
                         "_C: candle has no matmul kernel for U32 either.")
    )

    # dtype mismatch -- torch and the shim both refuse, with different words
    # (measured): torch raises "expected m1 and m2 to have the same dtype,
    # but got: float != double"; the shim's same_dtype refuses with its own
    # NotImplementedError. expect="both_error" only requires both refuse.
    f32_mm_t, f32_mm_c = pair_from_flat(torch_module, c_module, [1.0] * 4, (2, 2), "float32")
    f64_mm_t, f64_mm_c = pair_from_flat(torch_module, c_module, [1.0] * 4, (2, 2), "float64")
    cases.append(
        Case(
            name="matmul(float32 x float64 rejected on both sides)",
            op="aten.matmul.default",
            run_torch=lambda: torch_call(f32_mm_t, f64_mm_t),
            run_c=lambda: c_module._aten_dispatch("aten.matmul.default", f32_mm_c, f64_mm_c),
            expect="both_error",
            note="torch: 'expected m1 and m2 to have the same dtype, but got: float != double'; "
                 "_C: same_dtype refuses with its own message -- expect=both_error only needs both "
                 "to refuse, not to agree on wording.",
        )
    )

    # -- 1-D operands. torch's `matmul` has real vector rules (dot product,
    # matrix-vector, batched matrix-vector, all with the extra dimension
    # prepended/appended and then squeezed back out); this shim's
    # `matmul_default` refuses any operand under rank 2 outright rather than
    # guess at rules that were never measured (its own doc comment says so).
    # torch computes in every one of these; the shim refuses -- a real,
    # documented capability gap, not a shape error, hence expect="c_error"
    # rather than "both_error".
    for a_flat, a_shape, b_flat, b_shape, note in [
        ([1.0, 2.0, 3.0, 4.0], (4,), [1.0, 2.0, 3.0, 4.0], (4,), "1D x 1D -- dot product"),
        ([1.0, 2.0, 3.0], (3,), list(range(1, 13)), (3, 4), "1D x 2D -- vector-matrix"),
        (list(range(1, 13)), (4, 3), [1.0, 2.0, 3.0], (3,), "2D x 1D -- matrix-vector"),
        (list(range(1, 25)), (2, 4, 3), [1.0, 2.0, 3.0], (3,), "3D x 1D -- batched matrix-vector"),
        ([1.0, 2.0, 3.0], (3,), list(range(1, 25)), (2, 3, 4), "1D x 3D -- vector broadcast into a batch"),
    ]:
        cases.append(
            _matmul_case(torch_module, c_module, torch_call, "float32",
                        a_flat, a_shape, b_flat, b_shape, expect="c_error",
                        note=f"{note}; torch computes it, the shim's own doc comment says its "
                             "1-D vector rules were never measured and refuses unconditionally")
        )

    # -- model scale, checked against the scale-aware GEMM bound rather than a
    # flat tolerance (see `_gemm_scale_check`'s note). The transposed-view row
    # is the one that matters most: it is `(activation) x t(weight)` at the
    # depth (512) where mm_cases' own model-scale rows stop agreeing with
    # torch bitwise, so it is the strongest single check that the fold and
    # the layout fallback are both still computing the right numbers once
    # accumulation actually has somewhere to go wrong.
    cases.append(
        _matmul_model_case(torch_module, c_module, torch_call, "float32", 4, 8, 512, 8,
                           transpose_w=False,
                           note="contiguous weight, fold path -- gate/up_proj's depth")
    )
    cases.append(
        _matmul_model_case(torch_module, c_module, torch_call, "float32", 4, 8, 512, 8,
                           transpose_w=True,
                           note="t(weight) view, fold path -- the exact shape F.linear passes")
    )
    cases.append(
        _matmul_model_case(torch_module, c_module, torch_call, "float16", 1, 6, 512, 8,
                           transpose_w=True,
                           note="float16, batch=1 -- the accumulation-dtype question at F.linear's "
                                "own batch size")
    )

    return cases


# --- pre-seeded case builders for ops rust/torch_c does not implement yet --
#
# docs/C_SURFACE.md traced a small Llama forward+generate() against real
# upstream torch and found exactly 13 torch.<op> names actually get called
# (not just referenced -- called): arange, argmax, cat, embedding, empty,
# full, is_floating_point, isin, ones, pow, randint, rsqrt, tensor. `full`
# already has a builder above (aten.full.default, one of the three ops this
# harness started with). The other 12 are written here ahead of the
# implementation that is landing them in rust/torch_c, so the moment an op
# shows up in `_C._aten_implemented()` the golden comparison for it is
# already in place -- no gap between "implemented" and "checked".
#
# Until an op is actually implemented, `compare.py`'s `run()` simply never
# calls its builder (it only iterates `_aten_implemented()`), so having a
# builder registered here for an unimplemented op is inert: it costs
# nothing and cannot fail the run. `run()` prints how many are waiting
# under "PENDING", separately from the pass/fail count.
#
# Three of these ops don't produce a plain value-comparable tensor, so they
# use `Case.value_check` instead of relying on compare.py's default
# dtype/shape/value pipeline:
#   - `is_floating_point` returns a Python bool, not a 0-d Tensor.
#   - `empty` returns uninitialized memory -- there is no "correct" value
#     to diff, only dtype and shape are meaningful.
#   - `randint` returns a random draw. Two independent RNG implementations
#     (torch's CPU generator vs whatever rust/torch_c's backend uses)
#     produce different sequences even given "the same" seed -- a seed only
#     pins a *specific generator's* stream, it says nothing about another
#     generator's algorithm. There is no seed value that makes their
#     outputs equal, so this harness does not attempt to synchronize seeds
#     and instead checks dtype, shape, and that every value falls inside
#     the requested [low, high) range.


def _dtype_shape_only_check(t_res, c_res) -> tuple[bool, str]:
    """dtype + shape must agree; the values themselves are not meaningful
    (see `empty_cases` -- uninitialized memory has no "correct" value)."""
    t_dtype, c_dtype = dt.dtype_name(t_res.dtype), dt.dtype_name(c_res.dtype)
    if t_dtype != c_dtype:
        return False, f"dtype mismatch: torch={t_dtype} c={c_dtype}"
    t_shape = tuple(int(x) for x in t_res.shape)
    c_shape = tuple(int(x) for x in c_res.shape)
    if t_shape != c_shape:
        return False, f"shape mismatch: torch={t_shape} c={c_shape}"
    return True, f"dtype={t_dtype} shape={t_shape} (values unchecked -- uninitialized memory)"


def _flatten_values(x) -> list:
    if isinstance(x, list):
        out: list = []
        for v in x:
            out.extend(_flatten_values(v))
        return out
    return [x]


def _range_check(lo, hi):
    """dtype + shape must agree, and every value on both sides must land in
    [lo, hi); the *sequence* is deliberately not compared -- see the module
    note above on why two RNG implementations can't be seeded to match."""

    def check(t_res, c_res) -> tuple[bool, str]:
        t_dtype, c_dtype = dt.dtype_name(t_res.dtype), dt.dtype_name(c_res.dtype)
        if t_dtype != c_dtype:
            return False, f"dtype mismatch: torch={t_dtype} c={c_dtype}"
        t_shape = tuple(int(x) for x in t_res.shape)
        c_shape = tuple(int(x) for x in c_res.shape)
        if t_shape != c_shape:
            return False, f"shape mismatch: torch={t_shape} c={c_shape}"
        for label, res in (("torch", t_res), ("c", c_res)):
            for v in _flatten_values(res.tolist()):
                if not (lo <= v < hi):
                    return False, f"{label} produced {v!r}, outside requested range [{lo}, {hi})"
        return True, f"dtype={t_dtype} shape={t_shape}, all values within [{lo}, {hi}) (sequence unchecked -- see note above)"

    return check


def _scalar_match_check(t_res, c_res) -> tuple[bool, str]:
    """For ops returning a plain Python scalar rather than a Tensor (e.g.
    is_floating_point -> bool)."""
    if type(t_res) is not type(c_res):
        return (
            False,
            f"type mismatch: torch={type(t_res).__name__}({t_res!r}) c={type(c_res).__name__}({c_res!r})",
        )
    if t_res != c_res:
        return False, f"value mismatch: torch={t_res!r} c={c_res!r}"
    return True, f"scalar match: {t_res!r}"


# --- aten.arange.default / .start / .start_step -----------------------------

_ARANGE_INT_DTYPES = ["int64", "int32", "int16", "uint8", "uint32"]
_ARANGE_FLOAT_DTYPES = ["float64", "float32", "float16", "bfloat16"]


def arange_default_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.arange.default"
    cases: list[Case] = []

    for end, note in [(5, "dtype inferred from int end -> int64"), (0, "zero end -> empty result"), (1, "single element")]:
        cases.append(
            Case(
                name=f"arange(end={end}, dtype=inferred)",
                op=op,
                run_torch=lambda end=end: torch_call(end),
                run_c=lambda end=end: c_module._aten_dispatch(op, end),
                note=note,
            )
        )
    cases.append(
        Case(
            name="arange(end=5.0, dtype=inferred)",
            op=op,
            run_torch=lambda: torch_call(5.0),
            run_c=lambda: c_module._aten_dispatch(op, 5.0),
            note="dtype inferred from float end -> float32",
        )
    )

    for dtype_name in _ARANGE_INT_DTYPES + _ARANGE_FLOAT_DTYPES:
        t_dt = dt.torch_dtype(torch_module, dtype_name)
        c_dt = dt.c_dtype(c_module, dtype_name)
        for end in [0, 1, 20]:
            cases.append(
                Case(
                    name=f"arange(end={end}, dtype={dtype_name})",
                    op=op,
                    run_torch=lambda end=end, t_dt=t_dt: torch_call(end, dtype=t_dt),
                    run_c=lambda end=end, c_dt=c_dt: c_module._aten_dispatch(op, end, dtype=c_dt),
                    note="explicit dtype",
                )
            )

    cases.append(
        Case(
            name="arange(end=-1, negative end rejected)",
            op=op,
            run_torch=lambda: torch_call(-1),
            run_c=lambda: c_module._aten_dispatch(op, -1),
            expect="both_error",
            note="upper/lower bound sign inconsistent with (implicit) step -- torch refuses.",
        )
    )

    return cases


def arange_start_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.arange.start"
    cases: list[Case] = []

    for start, end, note in [
        (2, 5, "dtype inferred -> int64"),
        (-5, 5, "negative start, dtype inferred"),
        (3, 3, "start == end -> empty"),
    ]:
        cases.append(
            Case(
                name=f"arange(start={start}, end={end}, dtype=inferred)",
                op=op,
                run_torch=lambda start=start, end=end: torch_call(start, end),
                run_c=lambda start=start, end=end: c_module._aten_dispatch(op, start, end),
                note=note,
            )
        )

    for dtype_name in _ARANGE_INT_DTYPES + _ARANGE_FLOAT_DTYPES:
        t_dt = dt.torch_dtype(torch_module, dtype_name)
        c_dt = dt.c_dtype(c_module, dtype_name)
        start = 0 if dtype_name in ("uint8", "uint32") else -5
        cases.append(
            Case(
                name=f"arange(start={start}, end=10, dtype={dtype_name})",
                op=op,
                run_torch=lambda start=start, t_dt=t_dt: torch_call(start, 10, dtype=t_dt),
                run_c=lambda start=start, c_dt=c_dt: c_module._aten_dispatch(op, start, 10, dtype=c_dt),
                note="explicit dtype",
            )
        )

    cases.append(
        Case(
            name="arange(start=5, end=0, rejected -- wrong direction for implicit step=1)",
            op=op,
            run_torch=lambda: torch_call(5, 0),
            run_c=lambda: c_module._aten_dispatch(op, 5, 0),
            expect="both_error",
            note="start > end with an implicit positive step -- torch refuses rather than returning empty.",
        )
    )

    return cases


def arange_start_step_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.arange.start_step"
    cases: list[Case] = []

    for start, end, step, note in [
        (0, 10, 2, "positive step, dtype inferred -> int64"),
        (10, 0, -2, "negative step, dtype inferred"),
        (0, 1, 0.3, "fractional step -> dtype inferred float32"),
    ]:
        cases.append(
            Case(
                name=f"arange(start={start}, end={end}, step={step}, dtype=inferred)",
                op=op,
                run_torch=lambda start=start, end=end, step=step: torch_call(start, end, step),
                run_c=lambda start=start, end=end, step=step: c_module._aten_dispatch(op, start, end, step),
                note=note,
            )
        )

    for dtype_name in _ARANGE_FLOAT_DTYPES:
        t_dt = dt.torch_dtype(torch_module, dtype_name)
        c_dt = dt.c_dtype(c_module, dtype_name)
        cases.append(
            Case(
                name=f"arange(start=0, end=2, step=0.25, dtype={dtype_name})",
                op=op,
                run_torch=lambda t_dt=t_dt: torch_call(0, 2, 0.25, dtype=t_dt),
                run_c=lambda c_dt=c_dt: c_module._aten_dispatch(op, 0, 2, 0.25, dtype=c_dt),
                note="explicit float dtype, fractional step",
            )
        )

    for dtype_name in ["int64", "int32", "int16"]:
        t_dt = dt.torch_dtype(torch_module, dtype_name)
        c_dt = dt.c_dtype(c_module, dtype_name)
        cases.append(
            Case(
                name=f"arange(start=20, end=0, step=-3, dtype={dtype_name})",
                op=op,
                run_torch=lambda t_dt=t_dt: torch_call(20, 0, -3, dtype=t_dt),
                run_c=lambda c_dt=c_dt: c_module._aten_dispatch(op, 20, 0, -3, dtype=c_dt),
                note="explicit int dtype, negative step",
            )
        )

    cases.append(
        Case(
            name="arange(start=0, end=5, step=0, rejected)",
            op=op,
            run_torch=lambda: torch_call(0, 5, 0),
            run_c=lambda: c_module._aten_dispatch(op, 0, 5, 0),
            expect="both_error",
            note="step must be nonzero -- torch refuses.",
        )
    )
    cases.append(
        Case(
            name="arange(start=0, end=5, step=-1, sign-mismatched, rejected)",
            op=op,
            run_torch=lambda: torch_call(0, 5, -1),
            run_c=lambda: c_module._aten_dispatch(op, 0, 5, -1),
            expect="both_error",
            note="upper/lower bound sign inconsistent with step -- torch refuses.",
        )
    )

    return cases


# --- aten.amax.default -------------------------------------------------------
#
# `aten::amax(Tensor self, int[1] dim=[], bool keepdim=False) -> Tensor` -- the
# maximum *value*, no indices. docs/SEQLEN.md §7 is why it exists: SDPA's
# softmax wants a maximum for numerical stability and never wants the index,
# and candle only has the index-producing reduction.
#
# **Three of these cases exist because the family has form.** `max.default`
# answered `3.0` for `max([3, nan, 1])` where upstream answers `nan`, and every
# case that builder had passed throughout (docs/E2E_REAL.md); `max.other`
# dropped a NaN that was present only in its second operand
# (docs/SPELLINGS.md). Both are candle's `|x, y| x < y` predicate, which is
# false against a NaN and therefore skips one. So NaN is checked here from the
# first position, the middle and the last -- the middle one being the position
# a wrong kernel gets right by accident.

_AMAX_DTYPES = ["float64", "float32", "float16", "bfloat16", "int64", "int32"]


def amax_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.amax.default"
    cases: list[Case] = []

    scenarios = [
        dict(flat=[1, 5, 2, 9, 0, 3], shape=(2, 3), dim=[1], keepdim=False, note="along last dim"),
        dict(flat=[1, 5, 2, 9, 0, 3], shape=(2, 3), dim=[1], keepdim=True, note="along last dim, keepdim"),
        dict(flat=[1, 5, 2, 9, 0, 3], shape=(2, 3), dim=[0], keepdim=False, note="along first dim"),
        dict(flat=[1, 5, 2, 9, 0, 3], shape=(2, 3), dim=[-1], keepdim=False, note="dim=-1"),
        dict(flat=[1, 5, 2, 9, 0, 3], shape=(2, 3), dim=[0, 1], keepdim=False, note="both dims"),
        dict(flat=[1, 5, 2, 9, 0, 3], shape=(2, 3), dim=[0, 1], keepdim=True, note="both dims, keepdim"),
        # The schema default. It is *not* `sum.dim_IntList`'s reading of an
        # empty list (which reduces nothing) -- measured, `amax(a, [])` is a
        # scalar.
        dict(flat=[1, 5, 2, 9, 0, 3], shape=(2, 3), dim=[], keepdim=False, note="dim=[] reduces everything"),
        dict(flat=[-5, -1, -9, -3], shape=(2, 2), dim=[1], keepdim=False, note="all-negative values"),
        dict(flat=[7], shape=(1,), dim=[0], keepdim=False, note="single element"),
        dict(flat=[7], shape=(), dim=[], keepdim=False, note="0-d tensor, nothing to reduce"),
        # Rank 3, so the kernel's outer-dimension branch (strided slices) runs
        # as well as its innermost-dimension one (contiguous rows).
        dict(flat=list(range(24)), shape=(2, 3, 4), dim=[2], keepdim=False, note="3D, innermost dim"),
        dict(flat=list(range(24)), shape=(2, 3, 4), dim=[1], keepdim=False, note="3D, middle dim (strided slices)"),
        dict(flat=list(range(24)), shape=(2, 3, 4), dim=[0], keepdim=True, note="3D, outermost dim, keepdim"),
        # Longer than the kernel's 16 accumulator lanes, with the maximum past
        # the first full chunk -- a lane-combining bug survives every short row
        # above and dies here.
        dict(
            flat=[float(i % 7) for i in range(70)] + [99.0] + [1.0] * 9,
            shape=(2, 40),
            dim=[1],
            keepdim=False,
            note="rows longer than the 16 accumulator lanes, max in the tail",
        ),
    ]

    for dtype_name in _AMAX_DTYPES:
        for sc in scenarios:
            a_t, a_c = pair_from_flat(torch_module, c_module, sc["flat"], sc["shape"], dtype_name)
            dim, keepdim = sc["dim"], sc["keepdim"]
            cases.append(
                Case(
                    name=f"amax(dtype={dtype_name}, shape={sc['shape']}, dim={dim}, keepdim={keepdim}) [{sc['note']}]",
                    op=op,
                    run_torch=lambda a_t=a_t, dim=dim, keepdim=keepdim: torch_call(a_t, dim, keepdim),
                    run_c=lambda a_c=a_c, dim=dim, keepdim=keepdim: c_module._aten_dispatch(op, a_c, dim, keepdim),
                    note=sc["note"],
                )
            )

    # NaN, from every position a wrong reduction could skip. The `float32`
    # spelling is the one candle gets wrong today.
    nan = float("nan")
    for at, where in [(0, "first"), (1, "middle"), (3, "last")]:
        flat = [3.0, 5.0, 1.0, 2.0]
        flat[at] = nan
        for dtype_name in ["float64", "float32", "float16", "bfloat16"]:
            cases.append(
                _unary_case(
                    torch_module, c_module, op, torch_call, dtype_name, flat, (4,),
                    f"NaN in the {where} position propagates -- upstream's rule is IEEE "
                    f"maximum, and candle's reduction skips a NaN it does not start on",
                    kwargs=dict(dim=[0], keepdim=False),
                )
            )
    # A NaN far enough in that it lands in a later accumulator lane, which the
    # four-element rows above cannot reach.
    for dtype_name in ["float32", "float64"]:
        long_nan = [float(i) for i in range(40)]
        long_nan[23] = nan
        cases.append(
            _unary_case(
                torch_module, c_module, op, torch_call, dtype_name, long_nan, (40,),
                "NaN past the first accumulator chunk still reaches the result",
                kwargs=dict(dim=[0], keepdim=False),
            )
        )

    # A fully masked attention row. Every element `-inf` is a real shape in
    # causal attention, and the answer is `-inf` -- not NaN, and not the
    # neutral element of an empty fold.
    ninf = float("-inf")
    for dtype_name in ["float64", "float32", "float16", "bfloat16"]:
        cases.append(
            _unary_case(
                torch_module, c_module, op, torch_call, dtype_name, [ninf] * 5, (5,),
                "an all -inf row -- a fully masked attention row -- reduces to -inf",
                kwargs=dict(dim=[0], keepdim=False),
            )
        )
        cases.append(
            _unary_case(
                torch_module, c_module, op, torch_call, dtype_name, [ninf, ninf, -2.0, ninf], (4,),
                "-inf everywhere but one position",
                kwargs=dict(dim=[0], keepdim=False),
            )
        )
        cases.append(
            _unary_case(
                torch_module, c_module, op, torch_call, dtype_name,
                [ninf, ninf, ninf, ninf, ninf, ninf, ninf, ninf,
                 ninf, ninf, ninf, ninf, ninf, ninf, ninf, ninf, ninf, ninf], (18,),
                "an all -inf row longer than the accumulator lane count",
                kwargs=dict(dim=[0], keepdim=False),
            )
        )
        # +inf alongside -inf: the maximum is +inf, and nothing here may turn
        # the pair into a NaN the way a *sum*-shaped accumulator would.
        cases.append(
            _unary_case(
                torch_module, c_module, op, torch_call, dtype_name, [ninf, float("inf"), 0.0], (3,),
                "-inf and +inf in one row is +inf, not NaN",
                kwargs=dict(dim=[0], keepdim=False),
            )
        )

    # `torch.bool` -- amax keeps the input dtype rather than promoting, which
    # is the opposite of what `sum` does.
    cases.append(
        _unary_case(
            torch_module, c_module, op, torch_call, "bool", [1, 0, 0, 0], (2, 2),
            "bool input keeps torch.bool -- no int64 promotion, unlike sum",
            kwargs=dict(dim=[1], keepdim=False),
        )
    )

    # The refusals, all four measured on torch 2.13.0.
    err_t, err_c = pair_from_flat(torch_module, c_module, [1, 5, 2, 9, 0, 3], (2, 3), "float32")
    for name, dim in [
        ("a repeated dimension is refused (sum accepts one)", [1, 1]),
        ("a dimension out of range is refused", [5]),
    ]:
        cases.append(
            Case(
                name=f"amax({name})",
                op=op,
                run_torch=lambda t=err_t, dim=dim: torch_call(t, dim, False),
                run_c=lambda c=err_c, dim=dim: c_module._aten_dispatch(op, c, dim, False),
                expect="both_error",
                note=name,
            )
        )
    empty_t, empty_c = pair_from_flat(torch_module, c_module, [], (0,), "float32")
    cases.append(
        Case(
            name="amax(empty tensor with no dim named -- refused, and it is a RuntimeError)",
            op=op,
            run_torch=lambda: torch_call(empty_t, [], False),
            run_c=lambda: c_module._aten_dispatch(op, empty_c, [], False),
            expect="both_error",
            note="numel()==0 and dim=[] -- upstream asks for a dim by name",
        )
    )
    cases.append(
        Case(
            name="amax(a named reduction dim of extent zero -- refused, and it is an IndexError)",
            op=op,
            run_torch=lambda: torch_call(empty_t, [0], False),
            run_c=lambda: c_module._aten_dispatch(op, empty_c, [0], False),
            expect="both_error",
            note="numel()==0 with dim=[0] -- a different exception from the case above",
        )
    )

    # Keyword coverage, the same shape argmax_cases carries.
    kw_t, kw_c = pair_from_flat(torch_module, c_module, [1, 5, 2, 9, 0, 3], (2, 3), "float32")
    cases.append(
        Case(
            name="amax(self=/dim=/keepdim= all by keyword)",
            op=op,
            run_torch=lambda: torch_call(self=kw_t, dim=[1], keepdim=True),
            run_c=lambda: c_module._aten_dispatch(op, self=kw_c, dim=[1], keepdim=True),
        )
    )
    return cases


# --- aten.argmax.default -----------------------------------------------------

_ARGMAX_DTYPES = ["float64", "float32", "float16", "bfloat16", "int64", "int32"]


def argmax_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.argmax.default"
    cases: list[Case] = []

    # Flat values chosen so the maximum is unique in every reduced slice --
    # ties are broken by implementation-defined rules that torch and candle
    # need not agree on, and that disagreement would not be a real bug.
    scenarios = [
        dict(flat=[1, 5, 2, 9, 0, 3], shape=(2, 3), dim=None, keepdim=False, note="global argmax, flattened"),
        dict(flat=[1, 5, 2, 9, 0, 3], shape=(2, 3), dim=1, keepdim=False, note="argmax along last dim"),
        dict(flat=[1, 5, 2, 9, 0, 3], shape=(2, 3), dim=1, keepdim=True, note="argmax along last dim, keepdim"),
        dict(flat=[1, 5, 2, 9, 0, 3], shape=(2, 3), dim=0, keepdim=False, note="argmax along first dim"),
        dict(flat=[1, 5, 2, 9, 0, 3], shape=(2, 3), dim=-1, keepdim=False, note="argmax along dim=-1"),
        dict(flat=[7], shape=(1,), dim=None, keepdim=False, note="single element"),
        dict(
            flat=[1, 2, 3, 4, 5, 6, 7, 8, 9, 10, 11, 12],
            shape=(2, 3, 2),
            dim=2,
            keepdim=False,
            note="3D, argmax along last dim",
        ),
        dict(flat=[-5, -1, -9, -3], shape=(2, 2), dim=None, keepdim=False, note="all-negative values"),
    ]

    for dtype_name in _ARGMAX_DTYPES:
        for sc in scenarios:
            a_t, a_c = pair_from_flat(torch_module, c_module, sc["flat"], sc["shape"], dtype_name)
            dim, keepdim = sc["dim"], sc["keepdim"]
            cases.append(
                Case(
                    name=f"argmax(dtype={dtype_name}, shape={sc['shape']}, dim={dim}, keepdim={keepdim}) [{sc['note']}]",
                    op=op,
                    run_torch=lambda a_t=a_t, dim=dim, keepdim=keepdim: torch_call(a_t, dim, keepdim),
                    run_c=lambda a_c=a_c, dim=dim, keepdim=keepdim: c_module._aten_dispatch(op, a_c, dim, keepdim),
                )
            )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # self/dim/keepdim all by keyword -- also the "dim" tamper's own example.
    kw_t, kw_c = pair_from_flat(torch_module, c_module, [1, 5, 2, 9, 0, 3], (2, 3), "float32")
    cases.append(
        Case(
            name="argmax(self=/dim=/keepdim= all by keyword)",
            op=op,
            run_torch=lambda: torch_call(self=kw_t, dim=1, keepdim=True),
            run_c=lambda: c_module._aten_dispatch(op, self=kw_c, dim=1, keepdim=True),
        )
    )

    # NaN, and it is an *index* question here rather than a value one, which is
    # why none of the scenarios above could see it. Upstream: there is no
    # ordering under which a real number beats a NaN, so the reduction stops at
    # the first NaN it meets -- `argmax([1., nan, 3.])` is `1`, not `2`
    # (measured on torch 2.13.0). This build answered `2`: candle's fold is
    # `|x, y| x < y`, every comparison against a NaN is false, and the
    # accumulator never moves onto it. The same predicate, the same fault, as
    # `max.default` (docs/E2E_REAL.md), `max.other` (docs/SPELLINGS.md §7.2)
    # and `max.dim` (docs/TRIL.md §3).
    #
    # Three positions, and the first one is the trap: a NaN at index 0 seeds
    # the accumulator, so `argmax([nan, 2., 3.])` is `0` even with no NaN
    # handling at all. A suite with only that case passes under the bug --
    # the same hole docs/SEQLEN.md §7.12 found in `amax`'s first test.
    nan = float("nan")
    for at, where in [(0, "first"), (1, "middle"), (3, "last")]:
        flat = [1.0, 5.0, 2.0, 9.0]
        flat[at] = nan
        for dtype_name in ["float64", "float32", "float16", "bfloat16"]:
            for dim, keepdim, shape in [(None, False, (4,)), (0, False, (4,)), (0, True, (4,))]:
                a_t, a_c = pair_from_flat(torch_module, c_module, flat, shape, dtype_name)
                note = (
                    f"NaN in the {where} position wins the argmax -- upstream reports the "
                    f"index of the *first* NaN, and candle's fold skips a NaN it does not "
                    f"start on"
                )
                cases.append(
                    Case(
                        name=f"argmax(dtype={dtype_name}, shape={shape}, dim={dim}, keepdim={keepdim}) [{note}]",
                        op=op,
                        run_torch=lambda a_t=a_t, dim=dim, keepdim=keepdim: torch_call(a_t, dim, keepdim),
                        run_c=lambda a_c=a_c, dim=dim, keepdim=keepdim: c_module._aten_dispatch(
                            op, a_c, dim, keepdim
                        ),
                        note=note,
                    )
                )
    # Two NaNs: the *earlier* one wins, which distinguishes "report the first
    # NaN" from "report the last NaN" -- a mask reduction written with the
    # wrong tie-break passes every single-NaN case above.
    for dtype_name in ["float64", "float32"]:
        a_t, a_c = pair_from_flat(torch_module, c_module, [1.0, nan, 2.0, nan], (4,), dtype_name)
        note = "two NaNs -- the earlier index wins"
        cases.append(
            Case(
                name=f"argmax(dtype={dtype_name}, shape=(4,), dim=0) [{note}]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, 0, False),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, 0, False),
                note=note,
            )
        )
    # A NaN in one row of a 2-D input and not the other: the correction has to
    # be per-slice, not "the whole tensor has a NaN somewhere".
    for dtype_name in ["float64", "float32"]:
        a_t, a_c = pair_from_flat(
            torch_module, c_module, [1.0, nan, 2.0, 4.0, 9.0, 3.0], (2, 3), dtype_name
        )
        note = "NaN in the first row only -- the second row keeps its ordinary argmax"
        cases.append(
            Case(
                name=f"argmax(dtype={dtype_name}, shape=(2, 3), dim=1) [{note}]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, 1, False),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, 1, False),
                note=note,
            )
        )

    return cases


# --- aten.cat.default ---------------------------------------------------------

_CAT_DTYPES = ["float64", "float32", "float16", "bfloat16", "int64", "int32", "uint8"]


def cat_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.cat.default"
    cases: list[Case] = []

    for dtype_name in _CAT_DTYPES:
        a_t, a_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (2, 2), dtype_name)
        b_t, b_c = pair_from_flat(torch_module, c_module, [5, 6, 7, 8], (2, 2), dtype_name)
        cases.append(
            Case(
                name=f"cat(dtype={dtype_name}, dim=0, 2 tensors)",
                op=op,
                run_torch=lambda a_t=a_t, b_t=b_t: torch_call([a_t, b_t], 0),
                run_c=lambda a_c=a_c, b_c=b_c: c_module._aten_dispatch(op, [a_c, b_c], 0),
            )
        )
        cases.append(
            Case(
                name=f"cat(dtype={dtype_name}, dim=1, 2 tensors)",
                op=op,
                run_torch=lambda a_t=a_t, b_t=b_t: torch_call([a_t, b_t], 1),
                run_c=lambda a_c=a_c, b_c=b_c: c_module._aten_dispatch(op, [a_c, b_c], 1),
            )
        )
        cases.append(
            Case(
                name=f"cat(dtype={dtype_name}, dim=-1, 2 tensors)",
                op=op,
                run_torch=lambda a_t=a_t, b_t=b_t: torch_call([a_t, b_t], -1),
                run_c=lambda a_c=a_c, b_c=b_c: c_module._aten_dispatch(op, [a_c, b_c], -1),
            )
        )

    # 1D unequal-length concat along the only dim -- common for KV-cache-style growth.
    a1_t, a1_c = pair_from_flat(torch_module, c_module, [1.0, 2.0], (2,), "float32")
    b1_t, b1_c = pair_from_flat(torch_module, c_module, [3.0, 4.0, 5.0], (3,), "float32")
    cases.append(
        Case(
            name="cat(dtype=float32, 1D unequal lengths, dim=0)",
            op=op,
            run_torch=lambda: torch_call([a1_t, b1_t], 0),
            run_c=lambda: c_module._aten_dispatch(op, [a1_c, b1_c], 0),
            note="unequal length along the concat dim, as in incremental KV-cache growth",
        )
    )

    # Three tensors at once.
    c1_t, c1_c = pair_from_flat(torch_module, c_module, [1.0, 2.0], (1, 2), "float32")
    c2_t, c2_c = pair_from_flat(torch_module, c_module, [3.0, 4.0], (1, 2), "float32")
    c3_t, c3_c = pair_from_flat(torch_module, c_module, [5.0, 6.0], (1, 2), "float32")
    cases.append(
        Case(
            name="cat(dtype=float32, dim=0, 3 tensors)",
            op=op,
            run_torch=lambda: torch_call([c1_t, c2_t, c3_t], 0),
            run_c=lambda: c_module._aten_dispatch(op, [c1_c, c2_c, c3_c], 0),
        )
    )

    # Mismatched non-cat-dim shapes -- both sides must refuse.
    m1_t, m1_c = pair_from_flat(torch_module, c_module, [0.0] * 6, (2, 3), "float32")
    m2_t, m2_c = pair_from_flat(torch_module, c_module, [0.0] * 8, (2, 4), "float32")
    cases.append(
        Case(
            name="cat(mismatched non-cat-dim shapes rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call([m1_t, m2_t], 0),
            run_c=lambda: c_module._aten_dispatch(op, [m1_c, m2_c], 0),
            expect="both_error",
            note="shapes disagree outside the concat dim.",
        )
    )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # tensors/dim both by keyword.
    kwa_t, kwa_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (2, 2), "float32")
    kwb_t, kwb_c = pair_from_flat(torch_module, c_module, [5, 6, 7, 8], (2, 2), "float32")
    cases.append(
        Case(
            name="cat(tensors=/dim= both by keyword)",
            op=op,
            run_torch=lambda: torch_call(tensors=[kwa_t, kwb_t], dim=0),
            run_c=lambda: c_module._aten_dispatch(op, tensors=[kwa_c, kwb_c], dim=0),
        )
    )

    # `torch.concat` -- `zoedepth`'s wall after `relu_` (docs/KERNELS26.md
    # §21). `aten::concat` is `CompositeImplicitAutograd` and its body is
    # `at::cat`; a `TorchDispatchMode` trace fires `aten.cat.default` and
    # nothing else, so the alias is a `bootstrap.py` composite and golden is
    # blind to it by dispatch key. Deleting it fails these and nothing else.
    for dim, spelling in ((0, "torch.concat([a, b], dim=0)"),
                          (1, "torch.concat([a, b], 1) [positional]")):
        pa = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (2, 2), "float32")
        pb = pair_from_flat(torch_module, c_module, [5, 6, 7, 8], (2, 2), "float32")
        cases.append(
            _member_case(
                torch_module, c_module, op, f"spelling {spelling}", "float32",
                [pa, pb],
                lambda m, a, b, dim=dim: _free(m, "concat")([a, b], dim),
                note="an alias for cat, not an op of its own",
            )
        )
    pa = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (2, 2), "float32")
    pb = pair_from_flat(torch_module, c_module, [5, 6, 7, 8], (2, 2), "float32")
    cases.append(
        _member_case(
            torch_module, c_module, op,
            "spelling torch.concat(mismatched shapes) [refused]", "float32",
            [pa, pair_from_flat(torch_module, c_module, [0.0] * 6, (2, 3), "float32")],
            lambda m, a, b: _free(m, "concat")([a, b], 0),
            expect="both_error",
            note="the alias inherits cat's refusal rather than having its own",
        )
    )

    return cases


# --- aten.embedding.default ---------------------------------------------------

_EMBEDDING_WEIGHT_DTYPES = ["float64", "float32", "float16", "bfloat16"]


def embedding_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.embedding.default"
    cases: list[Case] = []

    vocab, dim = 8, 4
    weight_flat = [float(i) * 0.1 for i in range(vocab * dim)]

    for dtype_name in _EMBEDDING_WEIGHT_DTYPES:
        w_t, w_c = pair_from_flat(torch_module, c_module, weight_flat, (vocab, dim), dtype_name)

        idx_1d_t, idx_1d_c = pair_from_flat(torch_module, c_module, [0, 3, 7, 2], (4,), "int64")
        cases.append(
            Case(
                name=f"embedding(weight_dtype={dtype_name}, indices=1D)",
                op=op,
                run_torch=lambda w_t=w_t, idx_1d_t=idx_1d_t: torch_call(w_t, idx_1d_t),
                run_c=lambda w_c=w_c, idx_1d_c=idx_1d_c: c_module._aten_dispatch(op, w_c, idx_1d_c),
                note="token-embedding-lookup shape",
            )
        )

        idx_2d_t, idx_2d_c = pair_from_flat(torch_module, c_module, [0, 1, 2, 7, 6, 5], (2, 3), "int64")
        cases.append(
            Case(
                name=f"embedding(weight_dtype={dtype_name}, indices=2D batch)",
                op=op,
                run_torch=lambda w_t=w_t, idx_2d_t=idx_2d_t: torch_call(w_t, idx_2d_t),
                run_c=lambda w_c=w_c, idx_2d_c=idx_2d_c: c_module._aten_dispatch(op, w_c, idx_2d_c),
                note="batch x sequence indices shape, as in a real forward pass",
            )
        )

        idx_edge_t, idx_edge_c = pair_from_flat(torch_module, c_module, [0, 0, vocab - 1, vocab - 1], (4,), "int64")
        cases.append(
            Case(
                name=f"embedding(weight_dtype={dtype_name}, indices=boundary 0/vocab-1)",
                op=op,
                run_torch=lambda w_t=w_t, idx_edge_t=idx_edge_t: torch_call(w_t, idx_edge_t),
                run_c=lambda w_c=w_c, idx_edge_c=idx_edge_c: c_module._aten_dispatch(op, w_c, idx_edge_c),
                note="first and last valid row indices",
            )
        )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # weight/indices both by keyword.
    kw_w_t, kw_w_c = pair_from_flat(torch_module, c_module, weight_flat, (vocab, dim), "float32")
    kw_idx_t, kw_idx_c = pair_from_flat(torch_module, c_module, [0, 3, 7, 2], (4,), "int64")
    cases.append(
        Case(
            name="embedding(weight=/indices= both by keyword)",
            op=op,
            run_torch=lambda: torch_call(weight=kw_w_t, indices=kw_idx_t),
            run_c=lambda: c_module._aten_dispatch(op, weight=kw_w_c, indices=kw_idx_c),
        )
    )

    return cases


# --- aten.empty.memory_format --------------------------------------------------

_EMPTY_SHAPES: list[tuple[int, ...]] = [(), (3,), (2, 3), (0, 3), (1, 4, 1)]


def empty_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.empty.memory_format"
    cases: list[Case] = []

    for shape in _EMPTY_SHAPES:
        shape_list = list(shape)
        cases.append(
            Case(
                name=f"empty(shape={shape_list}, dtype=inferred)",
                op=op,
                run_torch=lambda shape_list=shape_list: torch_call(shape_list),
                run_c=lambda shape_list=shape_list: c_module._aten_dispatch(op, shape_list),
                value_check=_dtype_shape_only_check,
                note="uninitialized memory -- only dtype/shape are meaningful, see module note above",
            )
        )

    for dtype_name in dt.DEFAULT_DTYPES:
        c_dt = dt.c_dtype(c_module, dtype_name)
        t_dt = dt.torch_dtype(torch_module, dtype_name)
        cases.append(
            Case(
                name=f"empty(shape=[2, 3], dtype={dtype_name})",
                op=op,
                run_torch=lambda t_dt=t_dt: torch_call([2, 3], dtype=t_dt),
                run_c=lambda c_dt=c_dt: c_module._aten_dispatch(op, [2, 3], dtype=c_dt),
                value_check=_dtype_shape_only_check,
                note="uninitialized memory -- only dtype/shape are meaningful, see module note above",
            )
        )

    return cases


# --- aten.is_floating_point.default -------------------------------------------

_IS_FLOATING_POINT_DTYPES = ["float64", "float32", "float16", "bfloat16", "int64", "int32", "uint8"]


def is_floating_point_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.is_floating_point.default"
    cases: list[Case] = []

    for dtype_name in _IS_FLOATING_POINT_DTYPES:
        a_t, a_c = pair_from_flat(torch_module, c_module, [1, 2, 3], (3,), dtype_name)
        cases.append(
            Case(
                name=f"is_floating_point(dtype={dtype_name})",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c),
                value_check=_scalar_match_check,
                note="returns a plain Python bool, not a Tensor",
            )
        )

    for shape, dtype_name, note in [((), "float32", "0-d float"), ((2, 2), "int32", "2D int")]:
        flat = [1.0] if shape == () else [1, 2, 3, 4]
        a_t, a_c = pair_from_flat(torch_module, c_module, flat, shape, dtype_name)
        cases.append(
            Case(
                name=f"is_floating_point(dtype={dtype_name}, shape={shape})",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c),
                value_check=_scalar_match_check,
                note=f"returns a plain Python bool, not a Tensor -- {note} shape coverage",
            )
        )

    return cases


# --- aten.isin.Tensor_Tensor ---------------------------------------------------

_ISIN_DTYPES = ["float64", "float32", "int64", "int32", "uint8"]


def isin_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.isin.Tensor_Tensor"
    cases: list[Case] = []

    for dtype_name in _ISIN_DTYPES:
        elements_t, elements_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4, 5], (5,), dtype_name)
        test_t, test_c = pair_from_flat(torch_module, c_module, [2, 4], (2,), dtype_name)
        cases.append(
            Case(
                name=f"isin(dtype={dtype_name}, some matches)",
                op=op,
                run_torch=lambda e=elements_t, tt=test_t: torch_call(e, tt),
                run_c=lambda e=elements_c, tt=test_c: c_module._aten_dispatch(op, e, tt),
            )
        )

        empty_test_t, empty_test_c = pair_from_flat(torch_module, c_module, [], (0,), dtype_name)
        cases.append(
            Case(
                name=f"isin(dtype={dtype_name}, empty test_elements -> all False)",
                op=op,
                run_torch=lambda e=elements_t, tt=empty_test_t: torch_call(e, tt),
                run_c=lambda e=elements_c, tt=empty_test_c: c_module._aten_dispatch(op, e, tt),
            )
        )

        full_test_t, full_test_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4, 5], (5,), dtype_name)
        cases.append(
            Case(
                name=f"isin(dtype={dtype_name}, test_elements == elements -> all True)",
                op=op,
                run_torch=lambda e=elements_t, tt=full_test_t: torch_call(e, tt),
                run_c=lambda e=elements_c, tt=full_test_c: c_module._aten_dispatch(op, e, tt),
            )
        )

        cases.append(
            Case(
                name=f"isin(dtype={dtype_name}, invert=True)",
                op=op,
                run_torch=lambda e=elements_t, tt=test_t: torch_call(e, tt, invert=True),
                run_c=lambda e=elements_c, tt=test_c: c_module._aten_dispatch(op, e, tt, invert=True),
            )
        )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # elements/test_elements both by keyword.
    kw_e_t, kw_e_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4, 5], (5,), "float32")
    kw_t_t, kw_t_c = pair_from_flat(torch_module, c_module, [2, 4], (2,), "float32")
    cases.append(
        Case(
            name="isin(elements=/test_elements= both by keyword)",
            op=op,
            run_torch=lambda: torch_call(elements=kw_e_t, test_elements=kw_t_t),
            run_c=lambda: c_module._aten_dispatch(op, elements=kw_e_c, test_elements=kw_t_c),
        )
    )

    return cases


# --- aten.ones.default ---------------------------------------------------------

_ONES_SHAPES: list[tuple[int, ...]] = [(), (3,), (2, 3), (0, 3), (1, 4, 1)]


def ones_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.ones.default"
    cases: list[Case] = []

    for shape in _ONES_SHAPES:
        shape_list = list(shape)
        cases.append(
            Case(
                name=f"ones(shape={shape_list}, dtype=inferred)",
                op=op,
                run_torch=lambda shape_list=shape_list: torch_call(shape_list),
                run_c=lambda shape_list=shape_list: c_module._aten_dispatch(op, shape_list),
                note="dtype inferred -> torch.ones defaults to float32",
            )
        )

    for dtype_name in dt.DEFAULT_DTYPES:
        c_dt = dt.c_dtype(c_module, dtype_name)
        t_dt = dt.torch_dtype(torch_module, dtype_name)
        for shape in [(3,), (2, 3)]:
            shape_list = list(shape)
            cases.append(
                Case(
                    name=f"ones(shape={shape_list}, dtype={dtype_name})",
                    op=op,
                    run_torch=lambda shape_list=shape_list, t_dt=t_dt: torch_call(shape_list, dtype=t_dt),
                    run_c=lambda shape_list=shape_list, c_dt=c_dt: c_module._aten_dispatch(op, shape_list, dtype=c_dt),
                )
            )

    return cases


# --- aten.pow.Tensor_Scalar / .Tensor_Tensor / .Scalar ------------------------

_POW_FLOAT_DTYPES = ["float64", "float32", "float16", "bfloat16"]
_POW_INT_DTYPES = ["int64", "int32", "int16"]


def pow_tensor_scalar_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.pow.Tensor_Scalar"
    cases: list[Case] = []

    for dtype_name in _POW_FLOAT_DTYPES:
        base_t, base_c = pair_from_flat(torch_module, c_module, [0.0, 1.0, 2.0, -2.0, 4.0], (5,), dtype_name)
        for exponent, note in [(2, "square, int exponent -- RMSNorm-style"), (0, "x**0 -> 1"), (0.5, "sqrt via float exponent"), (-1, "negative exponent")]:
            cases.append(
                Case(
                    name=f"pow(dtype={dtype_name}, exponent={exponent}) [{note}]",
                    op=op,
                    run_torch=lambda base_t=base_t, exponent=exponent: torch_call(base_t, exponent),
                    run_c=lambda base_c=base_c, exponent=exponent: c_module._aten_dispatch(op, base_c, exponent),
                    note=note,
                )
            )

    for dtype_name in _POW_INT_DTYPES:
        base_t, base_c = pair_from_flat(torch_module, c_module, [0, 1, 2, -2, 4], (5,), dtype_name)
        cases.append(
            Case(
                name=f"pow(dtype={dtype_name}, exponent=2)",
                op=op,
                run_torch=lambda base_t=base_t: torch_call(base_t, 2),
                run_c=lambda base_c=base_c: c_module._aten_dispatch(op, base_c, 2),
                note="square, int exponent",
            )
        )
        cases.append(
            Case(
                name=f"pow(dtype={dtype_name}, exponent=-1, rejected)",
                op=op,
                run_torch=lambda base_t=base_t: torch_call(base_t, -1),
                run_c=lambda base_c=base_c: c_module._aten_dispatch(op, base_c, -1),
                expect="both_error",
                note="integers to negative integer powers are not allowed -- torch refuses.",
            )
        )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # self/exponent both by keyword.
    kw_base_t, kw_base_c = pair_from_flat(torch_module, c_module, [0.0, 1.0, 2.0, -2.0, 4.0], (5,), "float32")
    cases.append(
        Case(
            name="pow(self=/exponent= both by keyword)",
            op=op,
            run_torch=lambda: torch_call(self=kw_base_t, exponent=2),
            run_c=lambda: c_module._aten_dispatch(op, self=kw_base_c, exponent=2),
        )
    )

    # The scalar rule (docs/SCALAR.md §3.3), the *narrowing* half of it. Every
    # exponent above is 2, 0, 0.5 or -1 -- all exactly representable, so this
    # builder passed while the kernel used the parser's `f64` where upstream
    # uses `scalar_t`. Bases are positive so that a fractional exponent has a
    # real answer rather than nan; `float32` is included because this kernel has
    # no `opmath` widening at all, so narrowing is observable there too.
    cases.extend(
        _scalar_rule_cases(
            torch_module, c_module, op,
            lambda t, s: torch_call(t, s),
            lambda c, s: c_module._aten_dispatch(op, c, s),
            rule="narrow",
            why="pow_tensor_scalar_kernel converts the exponent to the "
                "dispatched scalar_t, not to opmath_t",
            # **`float32` is deliberately absent**, and not because the rule
            # stops there -- it does not, `float32` narrows too. Upstream's
            # `float32` `pow` answers *different bits for the same element
            # depending on the tensor's length* (measured: `f32([...8 values])
            # ** 0.3` disagrees with the same elements one at a time on 4 of 8;
            # SLEEF's vectorised `powf` against libm's on the tail). A case here
            # would be pinned to whichever road an 8-element tensor happens to
            # take, which is the shape of a test that passes for the wrong
            # reason. docs/SCALAR.md §3.3.
            dtypes=["float16", "bfloat16"],
            values=[3.0, 5.0, 7.0, 11.0, 13.0, 96.0, 2.0, 0.5],
        )
    )

    return cases


def pow_tensor_tensor_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.pow.Tensor_Tensor"
    cases: list[Case] = []

    for dtype_name in _POW_FLOAT_DTYPES:
        base_t, base_c = pair_from_flat(torch_module, c_module, [2.0, 3.0, 4.0, 0.0], (2, 2), dtype_name)
        exp_t, exp_c = pair_from_flat(torch_module, c_module, [2.0, 0.5, 0.0, 3.0], (2, 2), dtype_name)
        cases.append(
            Case(
                name=f"pow(dtype={dtype_name}, elementwise tensor exponent)",
                op=op,
                run_torch=lambda base_t=base_t, exp_t=exp_t: torch_call(base_t, exp_t),
                run_c=lambda base_c=base_c, exp_c=exp_c: c_module._aten_dispatch(op, base_c, exp_c),
            )
        )
        exp_scalar_t, exp_scalar_c = pair_from_flat(torch_module, c_module, [2.0], (), dtype_name)
        cases.append(
            Case(
                name=f"pow(dtype={dtype_name}, 0-d exponent broadcast)",
                op=op,
                run_torch=lambda base_t=base_t, exp_scalar_t=exp_scalar_t: torch_call(base_t, exp_scalar_t),
                run_c=lambda base_c=base_c, exp_scalar_c=exp_scalar_c: c_module._aten_dispatch(op, base_c, exp_scalar_c),
                note="scalar (0-d) broadcast",
            )
        )

    # --- MIXED dtypes: the promotion `bloom` needed (docs/ARCH20.md §6) -----
    #
    # **Every case above uses a same-dtype pair, so none of them could fail
    # when this op refused a mismatch by name.** That was found by sabotage:
    # reverting `pow.Tensor_Tensor` to `same_dtype` broke `bloom` and left the
    # golden suite entirely green. These are the cases that can fail.
    #
    # The grid was read off `pow.Tensor_Tensor`'s own result dtype over the
    # storable dtypes, not derived from `mul`'s table, and it agrees with
    # `torch._prims_common.get_higher_dtype` in every cell except `bool ** bool`
    # (below).
    for a_dtype, b_dtype, note in [
        ("float32", "int32", "bloom's own call: a float32 base to an int32 power"),
        ("float32", "int64", "an integral operand never widens a float"),
        ("float64", "float32", "the wider float wins"),
        ("int64", "int32", "the wider integer wins"),
        ("int32", "int16", "...and it is the width, not the argument order"),
        ("int32", "float16", "a float16 exponent floats an int32 base TO float16"),
        ("float16", "bfloat16", "two reduced floats escape UP to float32"),
        ("float16", "float16", "...but a same-rank identical pair does NOT escape"),
        # `int8` is deliberately absent: `_tensor_from_flat` cannot build one
        # (no candle storage for it), so `uint8 x int8 -> int16` is measured on
        # upstream and recorded in aten.rs rather than being a case here.
        ("uint8", "int16", "unsigned meets a wider signed: int16"),
        ("bool", "int32", "bool promotes out of its own category"),
    ]:
        base_t, base_c = pair_from_flat(torch_module, c_module, [2, 3], (2,), a_dtype)
        exp_t, exp_c = pair_from_flat(torch_module, c_module, [2, 1], (2,), b_dtype)
        cases.append(
            Case(
                name=f"pow(base={a_dtype}, exponent={b_dtype}) [{note}]",
                op=op,
                run_torch=lambda a=base_t, b=exp_t: torch_call(a, b),
                run_c=lambda a=base_c, b=exp_c: c_module._aten_dispatch(op, a, b),
                note=note,
            )
        )
    # The one cell where upstream raises rather than promoting.
    m_t, m_c = pair_from_flat(torch_module, c_module, [1, 0], (2,), "bool")
    n_t, n_c = pair_from_flat(torch_module, c_module, [1, 1], (2,), "bool")
    cases.append(
        Case(
            name="pow(bool, bool) [refused on both sides]",
            op=op,
            run_torch=lambda: torch_call(m_t, n_t),
            run_c=lambda: c_module._aten_dispatch(op, m_c, n_c),
            expect="both_error",
            note='NotImplementedError: "pow" not implemented for \'Bool\' -- the one cell '
                 "where the promotion table and upstream's behaviour part company",
        )
    )

    # --- negative integer exponents: `powi`, NOT a refusal ------------------
    #
    # Also found by sabotage: the shim refused these for all three overloads
    # while upstream refuses only `Tensor_Scalar`. `c10::powi` gives 1 for base
    # 1, +-1 for base -1 by the exponent's parity, and 0 otherwise -- so a
    # blanket `0` passes two of the four columns below and fails the other two.
    for exps, note in [
        ([-1, -1, -1, -1], "exponent -1 (odd): base -1 gives -1"),
        ([-2, -2, -2, -2], "exponent -2 (even): base -1 gives +1"),
        ([-3, 0, 2, -1], "mixed signs in one call, so the arms cannot be conflated"),
    ]:
        b_t, b_c = pair_from_flat(torch_module, c_module, [2, 1, -1, 0], (4,), "int64")
        e_t, e_c = pair_from_flat(torch_module, c_module, exps, (4,), "int64")
        cases.append(
            Case(
                name=f"pow(int64, int64 exponent={exps}) [{note}]",
                op=op,
                run_torch=lambda a=b_t, b=e_t: torch_call(a, b),
                run_c=lambda a=b_c, b=e_c: c_module._aten_dispatch(op, a, b),
                note=note,
            )
        )

    return cases


def pow_scalar_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.pow.Scalar"
    cases: list[Case] = []

    for dtype_name in _POW_FLOAT_DTYPES:
        exp_t, exp_c = pair_from_flat(torch_module, c_module, [1.0, 2.0, 3.0, 0.0], (2, 2), dtype_name)
        for base, note in [(2.0, "float base"), (0.0, "0**x"), (-1.0, "negative base")]:
            cases.append(
                Case(
                    name=f"pow(base={base}, dtype={dtype_name}, tensor exponent) [{note}]",
                    op=op,
                    run_torch=lambda base=base, exp_t=exp_t: torch_call(base, exp_t),
                    run_c=lambda base=base, exp_c=exp_c: c_module._aten_dispatch(op, base, exp_c),
                    note=note,
                )
            )

    # `pow.Scalar` shares `pow_from_pairs` with `Tensor_Tensor`, so it shares
    # `powi` -- and it too computes rather than refusing on a negative integer
    # exponent (measured: `pow.Scalar(2, [-1, 3])` is `[0, 8]`). Only
    # `Tensor_Scalar` refuses, which is asserted in its own builder.
    e_t, e_c = pair_from_flat(torch_module, c_module, [-1, 3, -2, 0], (4,), "int64")
    cases.append(
        Case(
            name="pow(base=2, int64 exponent with negatives) [computes, does NOT refuse]",
            op=op,
            run_torch=lambda: torch_call(2, e_t),
            run_c=lambda: c_module._aten_dispatch(op, 2, e_c),
            note="upstream [0, 8, 0, 1] -- the overload that refuses is Tensor_Scalar",
        )
    )

    # The scalar rule, on the *base* rather than the exponent (docs/SCALAR.md
    # §3.3). Same narrowing, same blind spot: every base above (2.0, 0.0, -1.0)
    # is exactly representable. The tensor here is the exponent, so its values
    # are small and exact and the scalar is what carries the rounding.
    cases.extend(
        _scalar_rule_cases(
            torch_module, c_module, op,
            lambda t, s: torch_call(s, t),
            lambda c, s: c_module._aten_dispatch(op, s, c),
            rule="narrow",
            why="pow_scalar's base goes through the same scalar_t conversion "
                "pow_tensor_scalar_kernel's exponent does",
            # `float32` absent for `pow.Tensor_Scalar`'s reason -- the same
            # length-dependence, seen here at exponent 0.5 of an 8-element
            # tensor: 1.1401753425598145 in the vector, 1.140175461769104 alone.
            dtypes=["float16", "bfloat16"],
            values=[1.0, 2.0, 3.0, 0.0, -1.0, 4.0, 0.5, -2.0],
        )
    )

    return cases


# --- aten.randint.low -----------------------------------------------------------
#
# See the module note above on random draws: dtype/shape/range are checked
# via Case.value_check, the sequence itself is not.

_RANDINT_DTYPES = ["int64", "int32", "int16"]


def randint_low_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.randint.low"
    cases: list[Case] = []

    scenarios = [
        dict(low=0, high=10, size=[5], note="1D, small positive range"),
        dict(low=-5, high=5, size=[4], note="range straddling zero"),
        dict(low=0, high=100, size=[2, 3], note="2D shape"),
        dict(low=0, high=1, size=[3], note="degenerate range -- only low itself is valid"),
    ]
    for sc in scenarios:
        low, high, size = sc["low"], sc["high"], sc["size"]
        for dtype_name in _RANDINT_DTYPES:
            t_dt = dt.torch_dtype(torch_module, dtype_name)
            c_dt = dt.c_dtype(c_module, dtype_name)
            cases.append(
                Case(
                    name=f"randint(low={low}, high={high}, size={size}, dtype={dtype_name}) [{sc['note']}]",
                    op=op,
                    run_torch=lambda low=low, high=high, size=size, t_dt=t_dt: torch_call(low, high, size, dtype=t_dt),
                    run_c=lambda low=low, high=high, size=size, c_dt=c_dt: c_module._aten_dispatch(
                        op, low, high, size, dtype=c_dt
                    ),
                    value_check=_range_check(low, high),
                    note=sc["note"] + " -- random draw, sequence unchecked (see module note above)",
                )
            )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # low/high/size/dtype all by keyword.
    kw_t_dt = dt.torch_dtype(torch_module, "int64")
    kw_c_dt = dt.c_dtype(c_module, "int64")
    cases.append(
        Case(
            name="randint(low=/high=/size=/dtype= all by keyword)",
            op=op,
            run_torch=lambda: torch_call(low=0, high=10, size=[5], dtype=kw_t_dt),
            run_c=lambda: c_module._aten_dispatch(op, low=0, high=10, size=[5], dtype=kw_c_dt),
            value_check=_range_check(0, 10),
        )
    )

    return cases


# --- aten.rsqrt.default ----------------------------------------------------------

_RSQRT_DTYPES = ["float64", "float32", "float16", "bfloat16"]


def rsqrt_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.rsqrt.default"
    cases: list[Case] = []

    for dtype_name in _RSQRT_DTYPES:
        for flat, shape, note in [
            ([1.0, 4.0, 9.0, 16.0], (2, 2), "perfect squares"),
            ([0.5, 2.0, 100.0, 0.01], (2, 2), "assorted magnitudes"),
            ([0.0], (1,), "zero -> +inf, RMSNorm epsilon should avoid this in practice"),
            ([-1.0, -4.0], (2,), "negative -> NaN"),
            ([1.0], (), "0-d"),
        ]:
            a_t, a_c = pair_from_flat(torch_module, c_module, flat, shape, dtype_name)
            cases.append(
                Case(
                    name=f"rsqrt(dtype={dtype_name}, shape={shape}) [{note}]",
                    op=op,
                    run_torch=lambda a_t=a_t: torch_call(a_t),
                    run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c),
                    note=note,
                )
            )

    return cases


# --- aten.sqrt.default -----------------------------------------------------
#
# `rsqrt` was here from the beginning and `sqrt` was not, which is the
# asymmetry docs/ARCH26.md §1 found blocking `deberta` and `deberta_v2`:
# both compute an attention temperature or a hand-rolled layer norm through
# `torch.sqrt` rather than through `nn.LayerNorm`.
#
# Two properties are checked here that `rsqrt`'s builder cannot check for it,
# because `rsqrt` destroys both:
#
#   * **`sqrt(-0.0)` is `-0.0`, not `+0.0`.** IEEE-754 says the sign of zero
#     survives the square root, and upstream agrees (measured on 2.13.0:
#     the result's bit pattern is `0x80000000`). `rsqrt(-0.0)` is `-inf`, so
#     the sign is visible there as a sign of infinity rather than of zero, and
#     an implementation that returned `+0.0` here would pass every `rsqrt`
#     case. Comparing by value alone would *also* miss it, because
#     `-0.0 == 0.0`, so the check is a dedicated `value_check` on the sign bit.
#   * **the integral rows.** `rsqrt`'s builder only runs the four float
#     dtypes; `sqrt(int64)` is `float32` (torch's unary-float promotion) and
#     that row is where a "keep the input dtype" implementation would fail.
#
# The domain rows (`-1.0 -> NaN`, `-inf -> NaN`) are the ones that separate a
# real `sqrt` from `pow(x, 0.5)`: `pow` on a negative base is NaN too, but
# `exp(0.5 * log(x))` -- candle's own `Tensor::pow` -- is NaN for a *different*
# reason and gets `sqrt(inf)` wrong. Nothing here is composed out of `pow`; the
# rows exist so that a future attempt to do so fails.

_SQRT_FLOAT_DTYPES = ["float64", "float32", "float16", "bfloat16"]
_SQRT_INT_DTYPES = ["int64", "int32", "int16", "uint8", "bool"]


def _signed_zero_check(t_res, c_res) -> tuple[bool, str]:
    """dtype, shape, every value -- and the *sign bit* of every zero.

    `_exact_value_check` above is the model, and this is that check plus one
    thing it cannot do: `-0.0 == 0.0` is true in Python, so an implementation
    that answered `+0.0` where upstream answers `-0.0` passes a bit-exact
    value comparison. `math.copysign` reads the bit that `==` throws away.

    Written as the superset rather than as a sign-only check on purpose: a
    comparator that looked at nothing but the sign bit would be blind to
    dtype, shape and every non-zero value, and `--self-test` would say so.
    """
    t_dtype, c_dtype = dt.dtype_name(t_res.dtype), dt.dtype_name(c_res.dtype)
    if t_dtype != c_dtype:
        return False, f"dtype mismatch: torch={t_dtype} c={c_dtype}"
    t_shape = tuple(int(x) for x in t_res.shape)
    c_shape = tuple(int(x) for x in c_res.shape)
    if t_shape != c_shape:
        return False, f"shape mismatch: torch={t_shape} c={c_shape}"
    t_vals = _flatten_values(t_res.tolist())
    c_vals = _flatten_values(c_res.tolist())
    if len(t_vals) != len(c_vals):
        return False, f"element count differs: torch={len(t_vals)} c={len(c_vals)}"
    zeros = 0
    for i, (t, c) in enumerate(zip(t_vals, c_vals)):
        if t != c and not (t != t and c != c):  # NaN == NaN for this purpose
            return False, f"value mismatch at index {i}: torch={t!r} c={c!r}"
        if t == 0.0:
            zeros += 1
            t_neg = math.copysign(1.0, float(t)) < 0
            c_neg = math.copysign(1.0, float(c)) < 0
            if t_neg != c_neg:
                return False, (
                    f"sign of zero differs at index {i}: "
                    f"torch={'-0.0' if t_neg else '+0.0'} "
                    f"c={'-0.0' if c_neg else '+0.0'} -- `-0.0 == 0.0` is true, "
                    "so a value comparison alone cannot see this"
                )
    return True, (
        f"dtype={t_dtype} shape={t_shape}, all {len(t_vals)} values equal and "
        f"{zeros} signed zero(s) carry the same sign bit"
    )


def _bitwise_equal_check(t_res, c_res) -> tuple[bool, str]:
    """Compares two results **bit for bit**, not within a tolerance.

    Written for `sigmoid`, where the interesting fault is a precision one and
    the harness's own `float16` tolerance is wide enough to hide it. Measured:
    evaluating `1/(1+exp(-x))` in `float16` instead of in `float32` and
    narrowing once disagrees with upstream on 6983 of 20000 random inputs --
    and every one of those disagreements is a 1-ULP difference, which
    `rtol=1e-3` absorbs completely. So this comparator asks for the bytes.

    That is the §0 trap ("a tolerance that cannot see the fault") in the one
    place this round could hit it, and the fix is the same one the f32
    precision cases needed: compare something the tolerance does not soften.

    Written as a **superset** of the default pipeline -- dtype, then shape,
    then values -- for the reason `_signed_zero_check` gives above and for a
    reason this comparator supplied itself: the first draft compared only the
    nested value lists, and `--self-test` immediately reported it accepting an
    injected *shape* fault and an injected *dtype* fault. A `value_check`
    replaces the whole pipeline; it does not extend it.
    """
    t_dtype, c_dtype = dt.dtype_name(t_res.dtype), dt.dtype_name(c_res.dtype)
    if t_dtype != c_dtype:
        return False, f"dtype mismatch: torch={t_dtype} c={c_dtype}"
    t_shape = tuple(int(x) for x in t_res.shape)
    c_shape = tuple(int(x) for x in c_res.shape)
    if t_shape != c_shape:
        return False, f"shape mismatch: torch={t_shape} c={c_shape}"
    t_vals = _flatten_values(t_res.tolist())
    c_vals = _flatten_values(c_res.tolist())
    if len(t_vals) != len(c_vals):
        return False, f"element count differs: torch={len(t_vals)} c={len(c_vals)}"
    for i, (a, b) in enumerate(zip(t_vals, c_vals)):
        if isinstance(a, float) and isinstance(b, float):
            if math.isnan(a) and math.isnan(b):
                continue
            if a != b:
                return False, (
                    f"not bit-equal at index {i}: torch={a!r} c={b!r} "
                    f"(|diff|={abs(a - b):.6g}) -- this comparator is exact on "
                    "purpose; the default tolerance would accept this"
                )
        elif a != b:
            return False, f"value mismatch at index {i}: torch={a!r} c={b!r}"
    return True, (
        f"dtype={t_dtype} shape={t_shape}, all {len(t_vals)} values bit-identical"
    )


_SIGMOID_FLOAT_DTYPES = ["float64", "float32", "float16", "bfloat16"]
_SIGMOID_INT_DTYPES = ["int64", "int32", "uint8", "bool"]


def sigmoid_cases(torch_module, c_module, torch_call) -> list[Case]:
    """`aten.sigmoid(Tensor self)` -- sam3_video's wall after `all`.

    The dtype rule is `unary_float`'s: an integral or boolean input promotes to
    the default float, unlike `silu`, which refuses one. The **precision** rule
    is `silu`'s and not the family's: `float16`/`bfloat16` are computed in
    `f32` and narrowed once.

    The plausible wrong implementations:

      * **another `Unary` variant** -- would evaluate in the input's own dtype,
        which is right for `tanh`/`exp` and wrong here on 6983/20000
        `float16` inputs by 1 ULP each. `_bitwise_equal_check` is what sees
        that; the default tolerance cannot.
      * **a copy of `silu`** -- would refuse an integral input, where upstream
        promotes it.
      * **`x / (1 + x.exp())`, the sign flipped** -- agrees at `x = 0`
        (both 0.5) and nowhere else; the asymmetric inputs below separate it.
      * **a guard for the saturating ends** -- unnecessary and a place to be
        wrong: `inf`/`-inf`/`nan`/`±100` all fall out of the formula.
    """
    op = "aten.sigmoid.default"
    cases: list[Case] = []

    for dtype_name in _SIGMOID_FLOAT_DTYPES:
        for flat, shape, note in [
            ([0.0], (1,), "sigmoid(0) is exactly 0.5"),
            ([1.0, -1.0, 2.5, -2.5], (2, 2), "asymmetric: a sign flip is visible"),
            ([0.5, -0.5, 8.0, -8.0], (2, 2), "assorted magnitudes"),
            ([float("inf"), float("-inf")], (2,), "+inf -> 1, -inf -> 0"),
            ([float("nan")], (1,), "NaN propagates"),
            ([100.0, -100.0], (2,), "saturates without a guard"),
            ([1.0], (), "0-d"),
            ([], (0,), "empty"),
        ]:
            a_t, a_c = pair_from_flat(torch_module, c_module, flat, shape, dtype_name)
            cases.append(
                Case(
                    name=f"sigmoid(dtype={dtype_name}, shape={shape}) [{note}]",
                    op=op,
                    run_torch=lambda a_t=a_t: torch_call(a_t),
                    run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c),
                    note=note,
                )
            )
        # The precision case, compared bit for bit -- but only at the two
        # reduced widths, and that limit is measured rather than conceded.
        #
        # `float16`/`bfloat16`: computing in `f32` and narrowing once is
        # bit-identical to upstream (0 of 20000 random inputs differ), while
        # computing in the reduced dtype differs on 6983 and 5466 of 20000 by
        # 1 ULP each -- which `rtol=1e-3` absorbs completely. This is the only
        # comparator that can see that fault.
        #
        # `float32`/`float64`: NOT bit-exact, and the residual is not this
        # kernel's. `aten.exp.default` itself already differs from upstream on
        # 12 of these 80 `f32` points and 16 of 80 in `f64` (candle's `exp`
        # versus upstream's vectorised one, ~1 ULP), and the sigmoid
        # mismatches land on exactly those indices -- measured. Demanding
        # bit-equality here would be demanding it of `exp`, which no other case
        # in this file does, so the wide widths stay on the default tolerance.
        spread = [x / 8.0 for x in range(-40, 40)]
        p_t, p_c = pair_from_flat(
            torch_module, c_module, spread, (len(spread),), dtype_name)
        reduced = dtype_name in ("float16", "bfloat16")
        cases.append(
            Case(
                name=f"sigmoid(dtype={dtype_name}, 80 values in [-5, 5])"
                     f"{' [BIT-EXACT]' if reduced else ''}",
                op=op,
                run_torch=lambda p_t=p_t: torch_call(p_t),
                run_c=lambda p_c=p_c: c_module._aten_dispatch(op, p_c),
                value_check=_bitwise_equal_check if reduced else None,
                note="f16/bf16 must be computed in f32 and narrowed once; "
                     "computing in the reduced dtype is 1 ULP out on ~35% of "
                     "inputs and the default tolerance cannot see it",
            )
        )

    # Integral and boolean inputs promote -- the half `silu` refuses.
    for dtype_name in _SIGMOID_INT_DTYPES:
        flat = [0, 1] if dtype_name == "bool" else [0, 1, 2, 3]
        shape = (2,) if dtype_name == "bool" else (2, 2)
        a_t, a_c = pair_from_flat(torch_module, c_module, flat, shape, dtype_name)
        cases.append(
            Case(
                name=f"sigmoid(dtype={dtype_name}) [integral -> default float, NOT refused]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c),
                note="unary-float promotion; silu refuses the same input",
            )
        )

    cases.extend(_sigmoid_member_cases(torch_module, c_module))
    return cases


def _sigmoid_member_cases(torch_module, c_module) -> list[Case]:
    """`x.sigmoid()` and `torch.sigmoid(x)` -- the two spellings.

    `sam3_video` uses the member. Golden compares by dispatch key and is blind
    to both, so deleting either table entry fails here and nothing else."""
    op = "aten.sigmoid.default"
    cases: list[Case] = []
    for dtype_name in ["float32", "float64", "int64"]:
        for spelling, call in (
            ("x.sigmoid()", lambda m, a: a.sigmoid()),
            ("torch.sigmoid(x)", lambda m, a: _free(m, "sigmoid")(a)),
        ):
            pair = pair_from_flat(torch_module, c_module, [1, -1, 2, -2], (2, 2), dtype_name)
            cases.append(
                _member_case(
                    torch_module, c_module, op,
                    f"spelling {spelling} (dtype={dtype_name})", dtype_name, [pair], call,
                    note="sam3_video squashes its logits through the member",
                )
            )
    return cases


def flip_cases(torch_module, c_module, torch_call) -> list[Case]:
    """`aten.flip(Tensor self, int[] dims)` -- vits' wall after `clamp_min`.

    `modeling_vits.py:595` reverses the channel order of the residual coupling
    layer's input on every flow step: `torch.flip(inputs, [1])`.

    The plausible wrong implementations, and what separates each:

      * **flipping the wrong axis** -- a `(2, 3)` case makes `flip([0])` and
        `flip([1])` different shapes of answer with the same shape of tensor,
        so both are here with distinct values. A square case would not
        separate them at all, which is why nothing here is square.
      * **normalising `-1` to `0`** -- `flip([-1])` must equal `flip([rank-1])`
        and not `flip([0])`. Both are cased, on the same non-square tensor.
      * **treating an empty `dims` as an error** -- upstream returns a copy.
      * **looping over `dims` without checking for a duplicate** -- flipping
        one axis twice is the identity, so a naive loop *returns the input*
        where upstream raises. `both_error`.
      * **returning a view** -- upstream copies (`data_ptr` differs). A shim
        that aliased would leak a write back into the base; the `_view_write`
        family is not applicable here, so the copy is asserted in
        `test_shim.py` instead, where `data_ptr` is visible.
    """
    op = "aten.flip.default"
    cases: list[Case] = []

    # Non-square on purpose: `flip([0])` and `flip([1])` produce different
    # answers only when the axes have different lengths *and* different
    # content, and a 2x2 of distinct values would still let a transposed
    # implementation through on shape.
    flat23 = [0, 1, 2, 3, 4, 5]
    for dtype_name in ["float32", "float64", "int64", "int32", "uint8", "bool", "float16"]:
        data = [x % 2 for x in flat23] if dtype_name == "bool" else flat23
        for dims, note in (
            ([0], "reverses the row ORDER"),
            ([1], "reverses WITHIN each row"),
            ([0, 1], "both axes"),
            ([-1], "negative dim normalises to the LAST axis, not the first"),
            ([-2], "negative dim, the other one"),
            ([], "empty dims is a COPY, not an error"),
        ):
            a_t, a_c = pair_from_flat(torch_module, c_module, data, (2, 3), dtype_name)
            cases.append(
                Case(
                    name=f"flip(dtype={dtype_name}, (2,3), dims={dims}) [{note}]",
                    op=op,
                    run_torch=lambda a_t=a_t, dims=dims: torch_call(a_t, dims),
                    run_c=lambda a_c=a_c, dims=dims: c_module._aten_dispatch(op, a_c, dims),
                    note=note,
                )
            )

    # Rank 3, so that "flip the last axis" and "flip the middle axis" are
    # distinguishable from each other as well as from the first.
    flat = list(range(24))
    for dims in ([0], [1], [2], [0, 2], [1, 2], [0, 1, 2]):
        a_t, a_c = pair_from_flat(torch_module, c_module, flat, (2, 3, 4), "float32")
        cases.append(
            Case(
                name=f"flip(float32, (2,3,4), dims={dims})",
                op=op,
                run_torch=lambda a_t=a_t, dims=dims: torch_call(a_t, dims),
                run_c=lambda a_c=a_c, dims=dims: c_module._aten_dispatch(op, a_c, dims),
                note="three distinct extents: an axis mix-up cannot survive this",
            )
        )

    # vits' exact call shape: flip axis 1 of a (batch, channels, time) tensor.
    v_t, v_c = pair_from_flat(
        torch_module, c_module, [float(x) for x in range(8)], (1, 4, 2), "float32")
    cases.append(
        Case(
            name="flip(float32, (1,4,2), dims=[1]) [vits' exact call shape]",
            op=op,
            run_torch=lambda: torch_call(v_t, [1]),
            run_c=lambda: c_module._aten_dispatch(op, v_c, [1]),
            note="modeling_vits.py:595 torch.flip(inputs, [1])",
        )
    )

    # Edge shapes.
    for flat, shape, dims, note in (
        ([7.0], (), [], "0-d with no dims"),
        ([], (0,), [0], "empty tensor, flipped"),
        ([1.0, 2.0, 3.0], (3,), [0], "rank 1"),
        ([1.0, 2.0, 3.0], (1, 3), [0], "a length-1 axis is its own reverse"),
    ):
        a_t, a_c = pair_from_flat(torch_module, c_module, flat, shape, "float32")
        cases.append(
            Case(
                name=f"flip(float32, {shape}, dims={dims}) [{note}]",
                op=op,
                run_torch=lambda a_t=a_t, dims=dims: torch_call(a_t, dims),
                run_c=lambda a_c=a_c, dims=dims: c_module._aten_dispatch(op, a_c, dims),
                note=note,
            )
        )

    # A duplicated dim is refused, NOT silently applied twice. This is the one
    # a "just loop over dims" implementation gets wrong, and it gets it wrong
    # by returning a plausible tensor -- the input, unchanged.
    d_t, d_c = pair_from_flat(torch_module, c_module, flat23, (2, 3), "int64")
    cases.append(
        Case(
            name="flip(int64, (2,3), dims=[0, 0]) [refused, NOT the identity]",
            op=op,
            run_torch=lambda: torch_call(d_t, [0, 0]),
            run_c=lambda: c_module._aten_dispatch(op, d_c, [0, 0]),
            expect="both_error",
            note='torch: "dim 0 appears multiple times in the list of dims"',
        )
    )
    # ...including when the duplicate is spelled with a negative index, which
    # a check written before normalisation would miss.
    d_t, d_c = pair_from_flat(torch_module, c_module, flat23, (2, 3), "int64")
    cases.append(
        Case(
            name="flip(int64, (2,3), dims=[1, -1]) [same axis, two spellings]",
            op=op,
            run_torch=lambda: torch_call(d_t, [1, -1]),
            run_c=lambda: c_module._aten_dispatch(op, d_c, [1, -1]),
            expect="both_error",
            note="the duplicate check has to run AFTER normalisation",
        )
    )
    # Out of range.
    o_t, o_c = pair_from_flat(torch_module, c_module, flat23, (2, 3), "int64")
    cases.append(
        Case(
            name="flip(int64, (2,3), dims=[5]) [out of range]",
            op=op,
            run_torch=lambda: torch_call(o_t, [5]),
            run_c=lambda: c_module._aten_dispatch(op, o_c, [5]),
            expect="both_error",
            note="torch: Dimension out of range (expected to be in range of [-2, 1])",
        )
    )

    cases.extend(_flip_member_cases(torch_module, c_module))
    return cases


def _flip_member_cases(torch_module, c_module) -> list[Case]:
    """`torch.flip(x, [1])` and `x.flip(1)` -- the two spellings.

    `vits` uses the free function. `TensorBase.flip` was named as missing in
    §14 of docs/KERNELS26.md and is the second caller; both table entries land
    in the same change and both are cased, because golden compares by dispatch
    key and is blind to either."""
    op = "aten.flip.default"
    cases: list[Case] = []
    for dtype_name in ["float32", "int64"]:
        for spelling, call in (
            ("torch.flip(x, [1])", lambda m, a: _free(m, "flip")(a, [1])),
            ("x.flip([1])", lambda m, a: a.flip([1])),
            ("x.flip(1)", lambda m, a: a.flip(1)),
        ):
            pair = pair_from_flat(
                torch_module, c_module, [0, 1, 2, 3, 4, 5], (2, 3), dtype_name)
            cases.append(
                _member_case(
                    torch_module, c_module, op,
                    f"spelling {spelling} (dtype={dtype_name})", dtype_name, [pair], call,
                    note="vits spells the free function; the member is the second caller",
                )
            )
    return cases


def sqrt_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.sqrt.default"
    cases: list[Case] = []

    for dtype_name in _SQRT_FLOAT_DTYPES:
        for flat, shape, note in [
            ([1.0, 4.0, 9.0, 16.0], (2, 2), "perfect squares"),
            ([2.0, 3.0, 0.5, 10.0], (2, 2), "irrational results"),
            ([0.5, 2.0, 100.0, 0.01], (2, 2), "assorted magnitudes"),
            ([0.0], (1,), "+0.0 -> +0.0"),
            ([-1.0, -4.0], (2,), "negative -> NaN"),
            ([float("inf")], (1,), "+inf -> +inf"),
            ([float("-inf")], (1,), "-inf -> NaN, not -inf"),
            ([float("nan")], (1,), "NaN -> NaN"),
            ([2.0], (), "0-d"),
            ([], (0,), "empty"),
        ]:
            a_t, a_c = pair_from_flat(torch_module, c_module, flat, shape, dtype_name)
            cases.append(
                Case(
                    name=f"sqrt(dtype={dtype_name}, shape={shape}) [{note}]",
                    op=op,
                    run_torch=lambda a_t=a_t: torch_call(a_t),
                    run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c),
                    note=note,
                )
            )

        # The signed zero, checked on its sign bit rather than its value.
        # Four elements rather than one so that the harness's `permute` and
        # `constant` fault modes can be built against this comparator too --
        # a one-element case leaves both of them "not applicable" and the
        # comparator is then only ever proved against `value`/`shape`/`dtype`.
        a_t, a_c = pair_from_flat(
            torch_module, c_module, [-0.0, 4.0, 0.0, 9.0], (2, 2), dtype_name
        )
        cases.append(
            Case(
                name=f"sqrt(dtype={dtype_name}) [-0.0 keeps its sign, +0.0 does too]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c),
                value_check=_signed_zero_check,
                note="IEEE-754: sqrt(-0.0) is -0.0. `-0.0 == 0.0`, so this "
                "needs the sign bit, not the value.",
            )
        )

    # Integral and boolean inputs promote to the default float -- the half of
    # the rule `rsqrt`'s float-only builder never reaches.
    for dtype_name in _SQRT_INT_DTYPES:
        flat = [0, 1] if dtype_name == "bool" else [0, 1, 4, 9]
        shape = (2,) if dtype_name == "bool" else (2, 2)
        a_t, a_c = pair_from_flat(torch_module, c_module, flat, shape, dtype_name)
        cases.append(
            Case(
                name=f"sqrt(dtype={dtype_name}, shape={shape}) [integral -> default float]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c),
                note="torch's unary-float promotion: not the input dtype",
            )
        )

    return cases


# --- aten.remainder.Scalar / aten.remainder.Tensor -------------------------
#
# `sam3_video`'s wall (docs/ARCH26.md §5): `Sam3ViTRotaryEmbedding.__init__`
# computes `x_positions = (flattened_indices % end_x) * scale`, which is
# `TensorBase.__mod__` and therefore `aten.remainder.Scalar`.
#
# **`remainder` follows the sign of the DIVISOR and `fmod` follows the sign of
# the dividend, and that is the classic way to get this wrong.** Every row of
# `_REMAINDER_SIGNS` below is a `(dividend, divisor)` pair whose two operands
# have signs that make the two conventions disagree, measured on upstream
# 2.13.0:
#
#     remainder( 7,  3) =  1     fmod =  1      (agree)
#     remainder( 7, -3) = -2     fmod =  1      <-- disagree
#     remainder(-7,  3) =  2     fmod = -1      <-- disagree
#     remainder(-7, -3) = -1     fmod = -1      (agree)
#
# An implementation written on `fmod` alone passes exactly half of these, and
# a case set that only used positive operands would pass all of them.
#
# Three more corners, all measured rather than assumed:
#
#   * **`remainder(-0.0, 3.0)` is `-0.0`**, not `+0.0`. Upstream's own
#     correction is `if (mod != 0) && ((b < 0) != (mod < 0)) mod += b`, and
#     `-0.0 != 0` is false, so the negative zero survives. Python's own
#     `-0.0 % 3.0` is `+0.0` -- so "just use Python's `%` semantics" is wrong
#     here, in a way `==` cannot see.
#   * **division by zero splits by category**: a float divisor of `0.0` gives
#     NaN, an integral one **raises** `RuntimeError('ZeroDivisionError')`.
#   * **infinities**: `remainder(5.0, -inf)` is `-inf` and
#     `remainder(-5.0, inf)` is `inf`, which fall straight out of the
#     correction above and are the rows that catch an implementation that
#     special-cases non-finite divisors.

_REMAINDER_DTYPES_FLOAT = ["float64", "float32", "float16", "bfloat16"]
_REMAINDER_DTYPES_INT = ["int64", "int32", "int16", "uint8"]

# The four sign quadrants, on both sides, in both directions.
_REMAINDER_SIGNS = [
    (7, 3), (7, -3), (-7, 3), (-7, -3),
    (0, 3), (0, -3),
    (5, 2), (-5, 2), (5, -2), (-5, -2),
    (1, 3), (-1, 3), (1, -3), (-1, -3),
    (6, 3), (-6, 3), (6, -3), (-6, -3),   # exact division in every quadrant
]


def remainder_scalar_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.remainder.Scalar"
    cases: list[Case] = []

    for dtype_name in _REMAINDER_DTYPES_FLOAT:
        for a, b in _REMAINDER_SIGNS:
            a_t, a_c = pair_from_flat(
                torch_module, c_module, [float(a)], (1,), dtype_name
            )
            cases.append(
                Case(
                    name=f"remainder({a}.0 as {dtype_name}, {b}.0) [sign of the divisor]",
                    op=op,
                    run_torch=lambda a_t=a_t, b=b: torch_call(a_t, float(b)),
                    run_c=lambda a_c=a_c, b=b: c_module._aten_dispatch(op, a_c, float(b)),
                    note="fmod would answer the sign of the dividend",
                )
            )
        # The signed zero, on its sign bit -- see `_signed_zero_check`.
        a_t, a_c = pair_from_flat(
            torch_module, c_module, [-0.0, 0.0, -0.0, 0.0], (2, 2), dtype_name
        )
        cases.append(
            Case(
                name=f"remainder(-0.0/+0.0 as {dtype_name}, 3.0) [signed zero survives]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, 3.0),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, 3.0),
                value_check=_signed_zero_check,
                note="upstream's correction is guarded by `mod != 0`, and "
                "`-0.0 != 0` is false -- Python's own `-0.0 % 3.0` is +0.0",
            )
        )
        # Non-finite operands, both sides.
        for a, b, note in [
            (float("inf"), 3.0, "inf dividend -> NaN"),
            (float("-inf"), 3.0, "-inf dividend -> NaN"),
            (float("nan"), 3.0, "NaN dividend -> NaN"),
            (5.0, float("inf"), "+inf divisor -> the dividend, unchanged"),
            (5.0, float("-inf"), "-inf divisor -> -inf, from the sign correction"),
            (-5.0, float("inf"), "+inf divisor, negative dividend -> +inf"),
            (5.0, 0.0, "float division by zero -> NaN, no raise"),
            (-5.0, 0.0, "float division by zero -> NaN, no raise"),
        ]:
            a_t, a_c = pair_from_flat(torch_module, c_module, [a], (1,), dtype_name)
            cases.append(
                Case(
                    name=f"remainder({a!r} as {dtype_name}, {b!r}) [{note}]",
                    op=op,
                    run_torch=lambda a_t=a_t, b=b: torch_call(a_t, b),
                    run_c=lambda a_c=a_c, b=b: c_module._aten_dispatch(op, a_c, b),
                    note=note,
                )
            )

    for dtype_name in _REMAINDER_DTYPES_INT:
        for a, b in _REMAINDER_SIGNS:
            if dtype_name == "uint8" and a < 0:
                continue  # the dividend would wrap; the divisor still varies
            a_t, a_c = pair_from_flat(torch_module, c_module, [a], (1,), dtype_name)
            cases.append(
                Case(
                    name=f"remainder({a} as {dtype_name}, {b}) [integral, sign of the divisor]",
                    op=op,
                    run_torch=lambda a_t=a_t, b=b: torch_call(a_t, b),
                    run_c=lambda a_c=a_c, b=b: c_module._aten_dispatch(op, a_c, b),
                    note="C's `%` truncates toward zero; torch's does not",
                )
            )
        # Integral division by zero RAISES, where the float path answers NaN.
        a_t, a_c = pair_from_flat(torch_module, c_module, [5], (1,), dtype_name)
        cases.append(
            Case(
                name=f"remainder({dtype_name}, 0) [integral division by zero raises]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, 0),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, 0),
                expect="both_error",
                note="upstream: RuntimeError('ZeroDivisionError') -- the float "
                "path answers NaN for the same input category",
            )
        )
        # An integral tensor with a FLOAT scalar floats the result.
        a_t, a_c = pair_from_flat(torch_module, c_module, [5], (1,), dtype_name)
        cases.append(
            Case(
                name=f"remainder({dtype_name}, 2.5) [float scalar floats the result]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, 2.5),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, 2.5),
                note="torch's wrapped-number rule: an int scalar would not",
            )
        )

    # `int64` min against `-1` -- the one pair where C's `%` is undefined and
    # Rust's panics. Upstream answers 0.
    a_t, a_c = pair_from_flat(torch_module, c_module, [-(2**63)], (1,), "int64")
    cases.append(
        Case(
            name="remainder(int64 min, -1) [the overflow pair]",
            op=op,
            run_torch=lambda a_t=a_t: torch_call(a_t, -1),
            run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, -1),
            note="`i64::MIN % -1` panics in Rust; upstream answers 0",
        )
    )

    # A documented capability gap: upstream computes for a bool tensor with a
    # numeric scalar (int64 for an int, float32 for a float) and this shim
    # refuses, the same way `arith_tag` refuses `bool_tensor * 2`.
    a_t, a_c = pair_from_flat(torch_module, c_module, [True, False], (2,), "bool")
    for scalar in (2, 2.0):
        cases.append(
            Case(
                name=f"remainder(bool, {scalar!r}) [documented gap: upstream computes]",
                op=op,
                run_torch=lambda a_t=a_t, s=scalar: torch_call(a_t, s),
                run_c=lambda a_c=a_c, s=scalar: c_module._aten_dispatch(op, a_c, s),
                expect="c_error",
                note="upstream gives int64 for an int scalar and float32 for a "
                "float one; this shim refuses bool operands here exactly as "
                "`arith_tag` already refuses `bool_tensor * 2`",
            )
        )

    return cases


def remainder_tensor_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.remainder.Tensor"
    cases: list[Case] = []

    for dtype_name in _REMAINDER_DTYPES_FLOAT + _REMAINDER_DTYPES_INT:
        is_float = dtype_name in _REMAINDER_DTYPES_FLOAT
        lhs = [a for a, _ in _REMAINDER_SIGNS]
        rhs = [b for _, b in _REMAINDER_SIGNS]
        if dtype_name == "uint8":
            lhs = [abs(v) for v in lhs]
            rhs = [abs(v) if v != 0 else 1 for v in rhs]
        if is_float:
            lhs = [float(v) for v in lhs]
            rhs = [float(v) for v in rhs]
        shape = (len(lhs),)
        a_t, a_c = pair_from_flat(torch_module, c_module, lhs, shape, dtype_name)
        b_t, b_c = pair_from_flat(torch_module, c_module, rhs, shape, dtype_name)
        cases.append(
            Case(
                name=f"remainder.Tensor(dtype={dtype_name}) [all four sign quadrants]",
                op=op,
                run_torch=lambda a_t=a_t, b_t=b_t: torch_call(a_t, b_t),
                run_c=lambda a_c=a_c, b_c=b_c: c_module._aten_dispatch(op, a_c, b_c),
                note="elementwise, every quadrant in one call",
            )
        )

    # Broadcasting, in both directions.
    a_t, a_c = pair_from_flat(
        torch_module, c_module, [7.0, 8.0], (2, 1), "float32"
    )
    b_t, b_c = pair_from_flat(torch_module, c_module, [3.0, -3.0], (2,), "float32")
    cases.append(
        Case(
            name="remainder.Tensor((2,1) against (2,)) [broadcast]",
            op=op,
            run_torch=lambda a_t=a_t, b_t=b_t: torch_call(a_t, b_t),
            run_c=lambda a_c=a_c, b_c=b_c: c_module._aten_dispatch(op, a_c, b_c),
            note="the sign correction has to be applied after broadcasting",
        )
    )
    cases.append(
        Case(
            name="remainder.Tensor((2,) against (2,1)) [broadcast, reversed]",
            op=op,
            run_torch=lambda a_t=b_t, b_t=a_t: torch_call(a_t, b_t),
            run_c=lambda a_c=b_c, b_c=a_c: c_module._aten_dispatch(op, a_c, b_c),
        )
    )

    # Mixed dtypes -- `remainder.Tensor` follows `torch.promote_types` exactly
    # (verified cell by cell over the eight storable numeric dtypes).
    for a_dt, b_dt in [
        ("int64", "int32"), ("int32", "float32"), ("float32", "float64"),
        ("float16", "float32"), ("float16", "bfloat16"), ("uint8", "int16"),
    ]:
        a_t, a_c = pair_from_flat(torch_module, c_module, [7], (1,), a_dt)
        b_t, b_c = pair_from_flat(torch_module, c_module, [3], (1,), b_dt)
        cases.append(
            Case(
                name=f"remainder.Tensor({a_dt} against {b_dt}) [promotion]",
                op=op,
                run_torch=lambda a_t=a_t, b_t=b_t: torch_call(a_t, b_t),
                run_c=lambda a_c=a_c, b_c=b_c: c_module._aten_dispatch(op, a_c, b_c),
                note="agrees with torch.promote_types in every measured cell",
            )
        )

    # Bool on both sides: upstream refuses too, with
    # `"remainder_cpu" not implemented for 'Bool'`.
    a_t, a_c = pair_from_flat(torch_module, c_module, [True, False], (2,), "bool")
    b_t, b_c = pair_from_flat(torch_module, c_module, [True, True], (2,), "bool")
    cases.append(
        Case(
            name="remainder.Tensor(bool, bool) [upstream refuses too]",
            op=op,
            run_torch=lambda a_t=a_t, b_t=b_t: torch_call(a_t, b_t),
            run_c=lambda a_c=a_c, b_c=b_c: c_module._aten_dispatch(op, a_c, b_c),
            expect="both_error",
            note='upstream: NotImplementedError \'"remainder_cpu" not implemented for \'Bool\'\'',
        )
    )

    # Integral division by zero, elementwise: one zero anywhere raises.
    a_t, a_c = pair_from_flat(torch_module, c_module, [5, 6], (2,), "int64")
    b_t, b_c = pair_from_flat(torch_module, c_module, [3, 0], (2,), "int64")
    cases.append(
        Case(
            name="remainder.Tensor(int64, [3, 0]) [one zero divisor raises]",
            op=op,
            run_torch=lambda a_t=a_t, b_t=b_t: torch_call(a_t, b_t),
            run_c=lambda a_c=a_c, b_c=b_c: c_module._aten_dispatch(op, a_c, b_c),
            expect="both_error",
            note="RuntimeError('ZeroDivisionError'), not a NaN in one lane",
        )
    )

    return cases


# --- aten.norm.ScalarOpt_dim -----------------------------------------------
#
# The third piece of `weight_norm`, and the one docs/KERNELS26.md §8.3 records
# as invisible to ARCH26.md's method: `torch.norm_except_dim` is a composite (so
# the op name never appears in the source) and it is called at CONSTRUCTION,
# while the trace that found `_weight_norm_interface` ran on a forward.
#
# **`p` is a general real exponent and five of its values are different
# functions.** Measured on 2.13.0:
#
#     p = None   ->  same as 2
#     p = 0      ->  the COUNT of non-zero elements
#     p = +inf   ->  max |x|
#     p = -inf   ->  min |x|
#     p = 1      ->  sum |x|
#     otherwise  ->  (sum |x|^p)^(1/p), fractional and NEGATIVE p included
#
# `norm_except_dim` only ever passes 2, so a case set built from the caller
# would exercise one of those six. The negative-`p` rows are the ones that
# catch a special-cased implementation: `norm([[0,0],[1,2]], p=-1, dim=1)` is
# `[0.0, 0.666...]`, because `|0|^-1` is `inf`, the sum is `inf`, and
# `inf^(-1)` is `0` -- it has to be special-cased *not* to happen.

_NORM_DTYPES = ["float64", "float32", "float16", "bfloat16"]
_NORM_PS = [None, 2, 1, 0, 3, 0.5, -1, -2, float("inf"), float("-inf")]


def norm_scalaropt_dim_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.norm.ScalarOpt_dim"
    cases: list[Case] = []

    # A non-square 2-D tensor with mixed signs and a zero, so |x| matters, the
    # axes are not interchangeable, and p=0 has something to count.
    flat = [3.0, -4.0, 0.0, 1.0, -1.0, 2.0]
    for dtype_name in _NORM_DTYPES:
        a_t, a_c = pair_from_flat(torch_module, c_module, flat, (2, 3), dtype_name)
        for p in _NORM_PS:
            for dim in ([0], [1], [-1], [0, 1], []):
                for keepdim in (False, True):
                    cases.append(
                        Case(
                            name=f"norm({dtype_name}, p={p!r}, dim={dim}, keepdim={keepdim})",
                            op=op,
                            run_torch=lambda a_t=a_t, p=p, dim=dim, k=keepdim: torch_call(
                                a_t, p, list(dim), k
                            ),
                            run_c=lambda a_c=a_c, p=p, dim=dim, k=keepdim: c_module._aten_dispatch(
                                op, a_c, p, list(dim), k
                            ),
                            note="an empty dim list reduces EVERY axis, which is "
                            "the opposite of the usual reading",
                        )
                    )
    # 3-D, so `norm_except_dim`'s real shape (a Conv1d weight) is covered and a
    # middle axis exists to get wrong.
    flat3 = [float(v) * 0.5 - 3.0 for v in range(2 * 3 * 4)]
    for dim in ([0], [1], [2], [0, 2], [1, 2]):
        a_t, a_c = pair_from_flat(torch_module, c_module, flat3, (2, 3, 4), "float64")
        cases.append(
            Case(
                name=f"norm(float64, 3-D (2,3,4), p=2, dim={dim}, keepdim=True)",
                op=op,
                run_torch=lambda a_t=a_t, dim=dim: torch_call(a_t, 2, list(dim), True),
                run_c=lambda a_c=a_c, dim=dim: c_module._aten_dispatch(
                    op, a_c, 2, list(dim), True
                ),
                note="the multi-axis reduction `norm_except_dim` is written on",
            )
        )
    # A zero row against negative and infinite p -- the corners that fall out of
    # the general formula and would be special-cased away by mistake.
    zeros = [0.0, 0.0, 1.0, 2.0]
    z_t, z_c = pair_from_flat(torch_module, c_module, zeros, (2, 2), "float64")
    for p in (-1, -2, float("inf"), float("-inf"), 0):
        cases.append(
            Case(
                name=f"norm(float64, a zero row, p={p!r}, dim=[1])",
                op=op,
                run_torch=lambda p=p: torch_call(z_t, p, [1], False),
                run_c=lambda p=p: c_module._aten_dispatch(op, z_c, p, [1], False),
                note="p=-1 over a zero row is 0.0, not inf: |0|^-1 is inf, the "
                "sum is inf, and inf^(-1) is 0",
            )
        )
    # An empty tensor reduces to 0.0, not to an error.
    e_t, e_c = pair_from_flat(torch_module, c_module, [], (2, 0), "float32")
    cases.append(
        Case(
            name="norm(float32, (2,0) empty, p=2, dim=[1])",
            op=op,
            run_torch=lambda: torch_call(e_t, 2, [1], False),
            run_c=lambda: c_module._aten_dispatch(op, e_c, 2, [1], False),
            note="an empty reduction is 0.0",
        )
    )
    # Integral and boolean input raise on both sides, with upstream's wording.
    for dtype_name in ("int64", "int32", "bool"):
        i_t, i_c = pair_from_flat(
            torch_module, c_module, [1, 0, 1, 1], (2, 2), dtype_name
        )
        cases.append(
            Case(
                name=f"norm({dtype_name}, p=2, dim=[1]) [both refuse]",
                op=op,
                run_torch=lambda i_t=i_t: torch_call(i_t, 2, [1], False),
                run_c=lambda i_c=i_c: c_module._aten_dispatch(op, i_c, 2, [1], False),
                expect="both_error",
                note="upstream: 'norm(): input dtype should be either floating "
                "point or complex. Got Long instead.'",
            )
        )
    # A repeated dim raises on both sides.
    r_t, r_c = pair_from_flat(torch_module, c_module, flat, (2, 3), "float32")
    cases.append(
        Case(
            name="norm(float32, dim=[0, 0]) [repeated dim, both refuse]",
            op=op,
            run_torch=lambda: torch_call(r_t, 2, [0, 0], False),
            run_c=lambda: c_module._aten_dispatch(op, r_c, 2, [0, 0], False),
            expect="both_error",
            note="upstream: 'dim 0 appears multiple times in the list of dims'",
        )
    )
    return cases


# --- aten._weight_norm_interface.default ------------------------------------
#
#     norms = norm_except_dim(v, 2, dim)     keep `dim`, reduce every other axis
#     out   = v * (g / norms)
#
# Both halves asserted against upstream rather than taken from the formula.
#
# **`dim` must be 0 or `v.dim() - 1`** -- upstream trips an `INTERNAL ASSERT
# FAILED` for anything else rather than raising a real error, so a middle dim is
# refused here by name and carried as `c_error`.
#
# **The norms come back float32 for a float16/bfloat16 input** while the output
# keeps the input dtype. That does not follow from anything else in this file
# and is read off upstream, so the reduced-float rows are the ones that catch it.


def _weight_norm_pair_check(t_res, c_res) -> tuple[bool, str]:
    """`(out, norms)` -- two float tensors, both compared within tolerance.

    `_pair_result_check` above cannot be reused: that one is for
    `(values, indices)` and requires its second member to match *exactly*,
    which is right for integer positions and wrong for a norm. Written as the
    full dtype/shape/value check on both members rather than as a check of
    `out` alone, because `norms` carries the one dtype rule this op has that
    nothing else in the file does (float32 for a reduced-float input).
    """
    try:
        t_parts = (t_res[0], t_res[1])
        c_parts = (c_res[0], c_res[1])
    except (TypeError, IndexError, KeyError) as e:
        return False, f"expected a 2-element (out, norms) result on both sides: {e!r}"
    for label, t_part, c_part in zip(("out", "norms"), t_parts, c_parts):
        t_dtype, c_dtype = dt.dtype_name(t_part.dtype), dt.dtype_name(c_part.dtype)
        if t_dtype != c_dtype:
            return False, f"{label} dtype mismatch: torch={t_dtype} c={c_dtype}"
        t_shape = tuple(int(x) for x in t_part.shape)
        c_shape = tuple(int(x) for x in c_part.shape)
        if t_shape != c_shape:
            return False, f"{label} shape mismatch: torch={t_shape} c={c_shape}"
        tol = dt.tolerance_for(t_dtype)
        t_flat = _flatten_values(t_part.tolist())
        c_flat = _flatten_values(c_part.tolist())
        if len(t_flat) != len(c_flat):
            return False, f"{label} length differs: torch={len(t_flat)} c={len(c_flat)}"
        for i, (x, y) in enumerate(zip(t_flat, c_flat)):
            xf, yf = float(x), float(y)
            # A zero row gives NaN on both sides; that agreement is the result.
            if math.isnan(xf) or math.isnan(yf):
                if math.isnan(xf) and math.isnan(yf):
                    continue
                return False, f"{label}[{i}] mismatch: torch={x!r} c={y!r} (NaN on one side only)"
            if not math.isclose(xf, yf, rel_tol=tol.rtol, abs_tol=tol.atol):
                return False, f"{label}[{i}] mismatch: torch={x!r} c={y!r}"
    return True, (
        f"(out, norms) agree: out dtype={dt.dtype_name(t_parts[0].dtype)} "
        f"shape={tuple(int(x) for x in t_parts[0].shape)}, "
        f"norms dtype={dt.dtype_name(t_parts[1].dtype)} "
        f"shape={tuple(int(x) for x in t_parts[1].shape)}"
    )


def weight_norm_interface_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten._weight_norm_interface.default"
    cases: list[Case] = []

    # 2-D, dim=0: `vits`'s shape (the default). Non-square and mixed sign.
    v_flat = [3.0, -4.0, 0.0, 1.0, -1.0, 2.0]
    for dtype_name in _NORM_DTYPES:
        v_t, v_c = pair_from_flat(torch_module, c_module, v_flat, (2, 3), dtype_name)
        g0_t, g0_c = pair_from_flat(torch_module, c_module, [2.0, -3.0], (2, 1), dtype_name)
        cases.append(
            Case(
                name=f"_weight_norm_interface({dtype_name}, v=(2,3), dim=0)",
                op=op,
                run_torch=lambda v_t=v_t, g_t=g0_t: torch_call(v_t, g_t, 0),
                run_c=lambda v_c=v_c, g_c=g0_c: c_module._aten_dispatch(op, v_c, g_c, 0),
                value_check=_weight_norm_pair_check,
                note="norms widen to float32 for float16/bfloat16 while out "
                "keeps the input dtype -- measured, not derived",
            )
        )
        # dim = v.dim()-1: `sew_d`'s form.
        g1_t, g1_c = pair_from_flat(
            torch_module, c_module, [1.0, 2.0, -0.5], (1, 3), dtype_name
        )
        cases.append(
            Case(
                name=f"_weight_norm_interface({dtype_name}, v=(2,3), dim=1 = v.dim()-1)",
                op=op,
                run_torch=lambda v_t=v_t, g_t=g1_t: torch_call(v_t, g_t, 1),
                run_c=lambda v_c=v_c, g_c=g1_c: c_module._aten_dispatch(op, v_c, g_c, 1),
                value_check=_weight_norm_pair_check,
                note="the other end of the supported range",
            )
        )
    # 3-D: a Conv1d weight, which is what both real callers actually pass.
    v3 = [float(x) * 0.3 - 2.0 for x in range(4 * 3 * 5)]
    v3_t, v3_c = pair_from_flat(torch_module, c_module, v3, (4, 3, 5), "float64")
    g30_t, g30_c = pair_from_flat(
        torch_module, c_module, [1.0, -2.0, 0.5, 3.0], (4, 1, 1), "float64"
    )
    cases.append(
        Case(
            name="_weight_norm_interface(float64, v=(4,3,5) Conv1d weight, dim=0) [vits]",
            op=op,
            run_torch=lambda: torch_call(v3_t, g30_t, 0),
            run_c=lambda: c_module._aten_dispatch(op, v3_c, g30_c, 0),
            value_check=_weight_norm_pair_check,
            note="vits: weight_norm(nn.Conv1d(...), name='weight') -- default dim=0",
        )
    )
    g32_t, g32_c = pair_from_flat(
        torch_module, c_module, [1.0, -1.0, 2.0, 0.5, -0.25], (1, 1, 5), "float64"
    )
    cases.append(
        Case(
            name="_weight_norm_interface(float64, v=(4,3,5) Conv1d weight, dim=2) [sew_d]",
            op=op,
            run_torch=lambda: torch_call(v3_t, g32_t, 2),
            run_c=lambda: c_module._aten_dispatch(op, v3_c, g32_c, 2),
            value_check=_weight_norm_pair_check,
            note="sew_d: weight_norm(self.conv, name='weight', dim=2) on a 3-D "
            "weight, which is v.dim()-1",
        )
    )
    # A zero row: the norm is 0 and the division is g/0, so upstream answers
    # NaN. Not special-cased on either side.
    vz_t, vz_c = pair_from_flat(
        torch_module, c_module, [0.0, 0.0, 1.0, 2.0], (2, 2), "float64"
    )
    gz_t, gz_c = pair_from_flat(torch_module, c_module, [2.0, 3.0], (2, 1), "float64")
    cases.append(
        Case(
            name="_weight_norm_interface(float64, a zero row, dim=0) [NaN, not a raise]",
            op=op,
            run_torch=lambda: torch_call(vz_t, gz_t, 0),
            run_c=lambda: c_module._aten_dispatch(op, vz_c, gz_c, 0),
            value_check=_weight_norm_pair_check,
            note="norm 0 and g/0 -> NaN on both sides; nothing is guarded",
        )
    )
    # Integral input: upstream refuses by kernel name.
    vi_t, vi_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (2, 2), "int64")
    gi_t, gi_c = pair_from_flat(torch_module, c_module, [1, 2], (2, 1), "int64")
    cases.append(
        Case(
            name="_weight_norm_interface(int64) [both refuse]",
            op=op,
            run_torch=lambda: torch_call(vi_t, gi_t, 0),
            run_c=lambda: c_module._aten_dispatch(op, vi_c, gi_c, 0),
            expect="both_error",
            note="upstream: '\"weight_norm_kernel\" not implemented for \\'Long\\''",
        )
    )
    # A v/g dtype mismatch raises rather than promoting.
    vm_t, vm_c = pair_from_flat(torch_module, c_module, v_flat, (2, 3), "float32")
    gm_t, gm_c = pair_from_flat(torch_module, c_module, [2.0, -3.0], (2, 1), "float64")
    cases.append(
        Case(
            name="_weight_norm_interface(v float32, g float64) [both refuse]",
            op=op,
            run_torch=lambda: torch_call(vm_t, gm_t, 0),
            run_c=lambda: c_module._aten_dispatch(op, vm_c, gm_c, 0),
            expect="both_error",
            note="upstream: 'expected scalar type Float but found Double' -- it "
            "does not promote",
        )
    )
    # A middle dim: upstream trips an INTERNAL ASSERT, this refuses by name.
    gmid_t, gmid_c = pair_from_flat(
        torch_module, c_module, [1.0, 2.0, 3.0], (1, 3, 1), "float64"
    )
    cases.append(
        Case(
            name="_weight_norm_interface(v=(4,3,5), dim=1) [a middle dim]",
            op=op,
            run_torch=lambda: torch_call(v3_t, gmid_t, 1),
            run_c=lambda: c_module._aten_dispatch(op, v3_c, gmid_c, 1),
            expect="both_error",
            note="upstream trips 'dim == 0 || dim == v.dim() - 1 INTERNAL ASSERT "
            "FAILED' rather than raising a real error; this refuses by name",
        )
    )
    return cases


# --- aten.div.Tensor_mode / aten.div.Scalar_mode ---------------------------
#
# `sam3_video`'s second wall, two lines after `remainder`'s (docs/ARCH26.md §5):
# `Sam3ViTRotaryEmbedding.__init__` builds the y axis of its rotary position
# grid with `torch.div(flattened_indices, end_x, rounding_mode="floor")`.
#
# **`rounding_mode` selects between three different functions**, and the case
# set has to be able to tell all three apart. Measured on upstream 2.13.0:
#
#         a    b   None      trunc   floor
#         7    3    2.333       2       2
#         7   -3   -2.333      -2      -3    <-- trunc/floor DISAGREE
#        -7    3   -2.333      -2      -3    <-- trunc/floor DISAGREE
#        -7   -3    2.333       2       2
#        -6    3   -2.0        -2      -2    <-- opposite signs, EXACT: agree
#     dtype    ->  float32   int64   int64
#
# `trunc` and `floor` differ **exactly when the operands' signs differ AND the
# division is inexact** -- established rather than asserted, over 210 integer
# pairs: they disagree on 64, that set contains no same-sign pair and no
# exact-division pair, and it is precisely the 64 opposite-sign inexact pairs.
# So two different case sets would each pass both implementations: one built
# from positive operands, and one built from opposite signs that divide exactly
# (`-6 / 3`). `_DIV_SIGNS` below carries all three kinds.
#
# **The float corners are where `floor(a / b)` -- the plausible implementation
# -- dies.** All measured:
#
#   * `inf / 3.0` is **nan**, not inf. `fmod(inf, 3.0)` is NaN and upstream's
#     algorithm propagates it.
#   * `5.0 / -inf` is **-1.0**, not -0.0, and `-5.0 / inf` is **-1.0** -- the
#     sign correction firing on a finite quotient of zero.
#   * `5.0 / 0.0` is **inf**, which is a *different* answer from `inf / 3.0`
#     even though both are non-finite: upstream returns the raw IEEE quotient
#     when `b == 0` and runs the algorithm otherwise.
#   * `-0.0 / 3.0` keeps its sign bit, which `==` cannot see.
#
# **Reduced-precision arithmetic is the trap that tolerance hides.** Upstream
# computes in the tensor's own dtype, not in f64. Computing in f64 and narrowing
# once is off by 1-2 ULP at large magnitudes -- and at those magnitudes a 1-ULP
# float32 error is ~8e-8 relative, comfortably *inside* this harness's float32
# rtol of 1e-5. The `_DIV_PRECISION` cases below therefore use
# `_exact_value_check`; under the default pipeline they would pass either way
# and prove nothing.
#
# **One measured upstream inconsistency, carried as `expect="diverge"`.** For
# float16/bfloat16 only, upstream's answer depends on the tensor's LENGTH: a
# one-element tensor computes in wider precision than a two-element one
# (measured at n = 1, 2, 4, 7, 8, 16, 17, 32, 64, 100 -- every n >= 2 agrees
# with every other, and only n == 1 differs, so it is a one-element fast path
# and not a vectorised-body/scalar-tail split). This shim computes in the
# tensor's own dtype, which is upstream's n >= 2 answer and therefore the answer
# every real tensor gets; the n == 1 cases record the disagreement so that it
# fails loudly if upstream ever unifies the two paths.

_DIV_MODE_FLOAT = ["float64", "float32", "float16", "bfloat16"]
_DIV_MODE_INT = ["int64", "int32", "int16", "uint8"]

# Same-sign, opposite-sign-inexact (where trunc and floor disagree), and
# opposite-sign-exact (where they agree, and so cannot tell them apart).
_DIV_SIGNS = [
    (7, 3), (7, -3), (-7, 3), (-7, -3),      # inexact, all four quadrants
    (6, 3), (6, -3), (-6, 3), (-6, -3),      # EXACT, all four quadrants
    (1, 3), (-1, 3), (1, -3), (-1, -3),      # |a| < |b|, quotient rounds to 0/-1
    (0, 3), (0, -3),                          # zero dividend
    (5, 2), (-5, 2), (5, -2), (-5, -2),
]

# (a, b) pairs where computing in f64 and narrowing gives a DIFFERENT answer
# from computing in the dtype itself. Found by search, then each one confirmed
# against upstream. Without these the f64 shortcut passes the whole suite.
_DIV_PRECISION: dict[str, list[tuple[float, float]]] = {
    "float32": [
        (8703144.0, -0.331771582365036),
        (13229698.0, -0.5165976285934448),
        (13088387.0, 0.9100134968757629),
        (9657791.0, 0.7925834059715271),
        (13277388.0, 2.04852032661438),
    ],
    "float16": [
        (-1121.0, -1.1806640625),
        (1050.0, -0.69873046875),
        (-1191.0, -0.26953125),
        (1706.0, -0.65185546875),
        (1582.0, 1.6044921875),
    ],
    "bfloat16": [
        (187.0, 0.83984375),
        (183.0, 0.51171875),
        (-163.0, 0.80078125),
        (190.0, 0.68359375),
        (212.0, 1.078125),
    ],
}

# (dtype, mode) -> an (a, b) pair whose answer upstream changes between a
# one-element tensor and a two-element one. Measured on both sides for each of
# the four; the divergence is mode-dependent, so a table keyed only on dtype
# produced a case that could not fail.
#
#   float16  floor  (-1121.0, -1.1806640625)  n=1: 949    n>=2: 948
#   float16  trunc  ( 1050.0, -0.69873046875) n=1: -1502  n>=2: -1503
#   bfloat16 floor  (  187.0,  0.83984375)    n=1: 222    n>=2: 221
#   bfloat16 trunc  (  190.0,  0.68359375)    n=1: 276    n>=2: 278
_DIV_N1_DIVERGENT: dict[tuple[str, str], tuple[float, float]] = {
    ("float16", "floor"): (-1121.0, -1.1806640625),
    ("float16", "trunc"): (1050.0, -0.69873046875),
    ("bfloat16", "floor"): (187.0, 0.83984375),
    ("bfloat16", "trunc"): (190.0, 0.68359375),
}

# The float corners, as (dividend, divisor, why).
_DIV_FLOAT_CORNERS = [
    (float("inf"), 3.0, "inf / finite is NaN, not inf -- fmod(inf, b) is NaN"),
    (float("-inf"), 3.0, "-inf / finite is NaN"),
    (float("nan"), 3.0, "NaN dividend stays NaN"),
    (5.0, float("inf"), "+inf divisor -> +0.0"),
    (5.0, float("-inf"), "-inf divisor -> -1.0 under floor, from the correction"),
    (-5.0, float("inf"), "negative dividend, +inf divisor -> -1.0 under floor"),
    (0.5, 3.0, "|a| < |b|, positive -> +0.0"),
    (-0.5, 3.0, "|a| < |b|, negative -> -1.0 under floor, -0.0 under trunc"),
    (5.0, 0.0, "float division by zero -> inf, NO raise (b == 0 early return)"),
    (-5.0, 0.0, "float division by zero -> -inf"),
    (0.0, 0.0, "0/0 -> NaN"),
]


def _div_mode_scalar_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.div.Scalar_mode"
    cases: list[Case] = []

    for mode in ("trunc", "floor"):
        for dtype_name in _DIV_MODE_INT:
            for a, b in _DIV_SIGNS:
                if dtype_name == "uint8" and a < 0:
                    continue
                a_t, a_c = pair_from_flat(torch_module, c_module, [a], (1,), dtype_name)
                cases.append(
                    Case(
                        name=f"div({a} as {dtype_name}, {b}, rounding_mode={mode!r})",
                        op=op,
                        run_torch=lambda a_t=a_t, b=b, m=mode: torch_call(a_t, b, rounding_mode=m),
                        run_c=lambda a_c=a_c, b=b, m=mode: c_module._aten_dispatch(
                            op, a_c, b, rounding_mode=m
                        ),
                        note="trunc and floor differ iff the signs differ and "
                        "the division is inexact; the dtype is PRESERVED, not "
                        "promoted to float as rounding_mode=None would",
                    )
                )
            # Integral division by zero raises -- but only under a rounding
            # mode. The same call with rounding_mode=None answers inf.
            a_t, a_c = pair_from_flat(torch_module, c_module, [5], (1,), dtype_name)
            cases.append(
                Case(
                    name=f"div({dtype_name}, 0, rounding_mode={mode!r}) [raises]",
                    op=op,
                    run_torch=lambda a_t=a_t, m=mode: torch_call(a_t, 0, rounding_mode=m),
                    run_c=lambda a_c=a_c, m=mode: c_module._aten_dispatch(
                        op, a_c, 0, rounding_mode=m
                    ),
                    expect="both_error",
                    note="RuntimeError('ZeroDivisionError'); rounding_mode=None "
                    "answers inf for the same input",
                )
            )
            # A float scalar floats an integral tensor (wrapped-number rule).
            a_t, a_c = pair_from_flat(torch_module, c_module, [7], (1,), dtype_name)
            cases.append(
                Case(
                    name=f"div({dtype_name}, 2.0, rounding_mode={mode!r}) [float scalar floats]",
                    op=op,
                    run_torch=lambda a_t=a_t, m=mode: torch_call(a_t, 2.0, rounding_mode=m),
                    run_c=lambda a_c=a_c, m=mode: c_module._aten_dispatch(
                        op, a_c, 2.0, rounding_mode=m
                    ),
                    note="an int scalar would leave the dtype alone",
                )
            )

        for dtype_name in _DIV_MODE_FLOAT:
            for a, b in _DIV_SIGNS:
                a_t, a_c = pair_from_flat(
                    torch_module, c_module, [float(a)], (1,), dtype_name
                )
                cases.append(
                    Case(
                        name=f"div({a}.0 as {dtype_name}, {b}.0, rounding_mode={mode!r})",
                        op=op,
                        run_torch=lambda a_t=a_t, b=b, m=mode: torch_call(
                            a_t, float(b), rounding_mode=m
                        ),
                        run_c=lambda a_c=a_c, b=b, m=mode: c_module._aten_dispatch(
                            op, a_c, float(b), rounding_mode=m
                        ),
                        note="floating dtype is preserved under both rounding modes",
                    )
                )
            for a, b, why in _DIV_FLOAT_CORNERS:
                a_t, a_c = pair_from_flat(torch_module, c_module, [a], (1,), dtype_name)
                cases.append(
                    Case(
                        name=f"div({a!r} as {dtype_name}, {b!r}, rounding_mode={mode!r}) [{why}]",
                        op=op,
                        run_torch=lambda a_t=a_t, b=b, m=mode: torch_call(
                            a_t, b, rounding_mode=m
                        ),
                        run_c=lambda a_c=a_c, b=b, m=mode: c_module._aten_dispatch(
                            op, a_c, b, rounding_mode=m
                        ),
                        note=why,
                    )
                )
            # The signed zero, on its sign bit.
            a_t, a_c = pair_from_flat(
                torch_module, c_module, [-0.0, 0.0, -0.0, 0.0], (2, 2), dtype_name
            )
            cases.append(
                Case(
                    name=f"div(-0.0/+0.0 as {dtype_name}, 3.0, rounding_mode={mode!r}) "
                    "[signed zero survives]",
                    op=op,
                    run_torch=lambda a_t=a_t, m=mode: torch_call(a_t, 3.0, rounding_mode=m),
                    run_c=lambda a_c=a_c, m=mode: c_module._aten_dispatch(
                        op, a_c, 3.0, rounding_mode=m
                    ),
                    value_check=_signed_zero_check,
                    expect="match",
                    note="upstream's copysign(0, a/b) branch; `-0.0 == 0.0` so "
                    "this needs the sign bit, not the value",
                )
            )

    # `uint8(200) / -3` is 0, because the scalar narrows to 253 in uint8 BEFORE
    # the division. The analogue of `remainder(uint8(200), -3) == 200`.
    a_t, a_c = pair_from_flat(torch_module, c_module, [200], (1,), "uint8")
    for mode in ("trunc", "floor"):
        cases.append(
            Case(
                name=f"div(uint8(200), -3, rounding_mode={mode!r}) [scalar narrows first]",
                op=op,
                run_torch=lambda a_t=a_t, m=mode: torch_call(a_t, -3, rounding_mode=m),
                run_c=lambda a_c=a_c, m=mode: c_module._aten_dispatch(
                    op, a_c, -3, rounding_mode=m
                ),
                note="-3 becomes 253 in uint8, so the answer is 0, not -66",
            )
        )

    # `i64::MIN / -1` overflows the quotient; upstream answers i64::MIN.
    a_t, a_c = pair_from_flat(torch_module, c_module, [-(2**63)], (1,), "int64")
    for mode in ("trunc", "floor"):
        cases.append(
            Case(
                name=f"div(int64 min, -1, rounding_mode={mode!r}) [the overflow pair]",
                op=op,
                run_torch=lambda a_t=a_t, m=mode: torch_call(a_t, -1, rounding_mode=m),
                run_c=lambda a_c=a_c, m=mode: c_module._aten_dispatch(
                    op, a_c, -1, rounding_mode=m
                ),
                note="`i64::MIN / -1` panics in Rust; upstream answers i64::MIN",
            )
        )

    # rounding_mode=None is true division: it PROMOTES where the other two
    # preserve, which is the row that tells the three modes apart by dtype.
    for dtype_name in ("int64", "int32", "float32"):
        a_t, a_c = pair_from_flat(torch_module, c_module, [7, -7], (2,), dtype_name)
        cases.append(
            Case(
                name=f"div({dtype_name}, 2, rounding_mode=None) [true division]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, 2, rounding_mode=None),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, 2, rounding_mode=None),
                note="int64 becomes float32 here and stays int64 under "
                "trunc/floor -- the dtype is how the modes are told apart",
            )
        )
    # ... and division by zero does NOT raise under None, where it does raise
    # under the other two. Same op, same operands, opposite kind of answer.
    a_t, a_c = pair_from_flat(torch_module, c_module, [5, -5, 0], (3,), "int64")
    cases.append(
        Case(
            name="div(int64, 0, rounding_mode=None) [no raise, unlike trunc/floor]",
            op=op,
            run_torch=lambda a_t=a_t: torch_call(a_t, 0, rounding_mode=None),
            run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, 0, rounding_mode=None),
            note="answers [inf, -inf, nan] as float32; trunc/floor raise",
        )
    )

    # An unrecognised rounding_mode is a RuntimeError on both sides.
    a_t, a_c = pair_from_flat(torch_module, c_module, [7], (1,), "int64")
    for bad in ("ceil", "", "Floor"):
        cases.append(
            Case(
                name=f"div(int64, 3, rounding_mode={bad!r}) [rejected by name]",
                op=op,
                run_torch=lambda a_t=a_t, s=bad: torch_call(a_t, 3, rounding_mode=s),
                run_c=lambda a_c=a_c, s=bad: c_module._aten_dispatch(
                    op, a_c, 3, rounding_mode=s
                ),
                expect="both_error",
                note="upstream: \"div expected rounding_mode to be one of None, "
                "'trunc', or 'floor'\" -- matched exactly and case-sensitively",
            )
        )

    # The reduced-float scalar rule, docs/SCALAR.md §3.2. `div_floor_kernel` and
    # `div_trunc_kernel` carry the same `original_scalar_value<opmath_t>(2)`
    # branch `div_true_kernel` does, so BOTH rounding modes widen -- and here a
    # single narrowing step does not shift the answer by one ULP, it shifts it by
    # a whole integer: bfloat16 `3 // 0.3` is 10 upstream and was 9 here.
    for mode in ("floor", "trunc"):
        cases.extend(
            _scalar_rule_cases(
                torch_module, c_module, op,
                lambda t, s, m=mode: torch_call(t, s, rounding_mode=m),
                lambda c, s, m=mode: c_module._aten_dispatch(op, c, s, rounding_mode=m),
                rule="widen",
                why=f"div_{mode}_kernel's reduced-float branch reads "
                    "original_scalar_value<opmath_t>(2) and computes "
                    f"div_{mode}_floating entirely in opmath",
                # **`_SCALAR_RULE_VALUES` cannot see this op** and sabotage F4
                # is what said so: at `[3, 5, 7, 11, 13, 96, -3, -5]` the two
                # rules agree for every scalar but two of six (dtype, scalar)
                # pairs, because upstream's fmod-based algorithm lands on the
                # same integer from either divisor at small magnitudes. These
                # values were measured to separate 4/8 at `bfloat16, 0.3`,
                # 3/8 at `float16, 0.7` and 8/8 at `float16, 0.1` -- and the
                # two dtypes need *different* scalars, which is why 0.1 is here
                # and is not in the shared list.
                values=[7.0, 14.0, 40.0, 43.0, 48.0, 61.0, 100.0, -49.0],
                separating=(0.3, 0.7, 1.3, 0.1),
            )
        )

    # A documented capability gap, identical in shape to `remainder.Scalar`'s:
    # upstream computes for a bool tensor with a numeric scalar and this shim
    # refuses, because the rule keys on the scalar's Python type.
    a_t, a_c = pair_from_flat(torch_module, c_module, [True, False], (2,), "bool")
    for scalar in (2, 2.0):
        for mode in ("trunc", "floor"):
            cases.append(
                Case(
                    name=f"div(bool, {scalar!r}, rounding_mode={mode!r}) "
                    "[documented gap: upstream computes]",
                    op=op,
                    run_torch=lambda a_t=a_t, s=scalar, m=mode: torch_call(
                        a_t, s, rounding_mode=m
                    ),
                    run_c=lambda a_c=a_c, s=scalar, m=mode: c_module._aten_dispatch(
                        op, a_c, s, rounding_mode=m
                    ),
                    expect="c_error",
                    note="upstream gives int64 for an int scalar and float32 for "
                    "a float one, and raises for a bool one; `scalar_arg` has "
                    "erased the Python type before the kernel runs -- the same "
                    "gap `remainder.Scalar` carries",
                )
            )

    return cases


def _div_mode_tensor_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.div.Tensor_mode"
    cases: list[Case] = []

    for mode in ("trunc", "floor"):
        # All the sign quadrants at once, per dtype, as a real tensor pair.
        for dtype_name in _DIV_MODE_FLOAT + _DIV_MODE_INT:
            signs = [
                (a, b) for a, b in _DIV_SIGNS
                if not (dtype_name == "uint8" and (a < 0 or b < 0))
            ]
            conv = float if dtype_name in _DIV_MODE_FLOAT else int
            a_t, a_c = pair_from_flat(
                torch_module, c_module, [conv(a) for a, _ in signs], (len(signs),), dtype_name
            )
            b_t, b_c = pair_from_flat(
                torch_module, c_module, [conv(b) for _, b in signs], (len(signs),), dtype_name
            )
            cases.append(
                Case(
                    name=f"div.Tensor_mode({dtype_name}, rounding_mode={mode!r}) "
                    "[every sign quadrant, exact and inexact]",
                    op=op,
                    run_torch=lambda a_t=a_t, b_t=b_t, m=mode: torch_call(
                        a_t, b_t, rounding_mode=m
                    ),
                    run_c=lambda a_c=a_c, b_c=b_c, m=mode: c_module._aten_dispatch(
                        op, a_c, b_c, rounding_mode=m
                    ),
                    note="includes the opposite-sign EXACT pairs, on which "
                    "trunc and floor agree and so cannot be told apart",
                )
            )

        # The float corners as one tensor per dtype.
        for dtype_name in _DIV_MODE_FLOAT:
            a_t, a_c = pair_from_flat(
                torch_module, c_module, [a for a, _, _ in _DIV_FLOAT_CORNERS],
                (len(_DIV_FLOAT_CORNERS),), dtype_name,
            )
            b_t, b_c = pair_from_flat(
                torch_module, c_module, [b for _, b, _ in _DIV_FLOAT_CORNERS],
                (len(_DIV_FLOAT_CORNERS),), dtype_name,
            )
            cases.append(
                Case(
                    name=f"div.Tensor_mode({dtype_name}, rounding_mode={mode!r}) "
                    "[inf/nan/zero corners]",
                    op=op,
                    run_torch=lambda a_t=a_t, b_t=b_t, m=mode: torch_call(
                        a_t, b_t, rounding_mode=m
                    ),
                    run_c=lambda a_c=a_c, b_c=b_c, m=mode: c_module._aten_dispatch(
                        op, a_c, b_c, rounding_mode=m
                    ),
                    value_check=_signed_zero_check,
                    note="`inf / 3.0` is NaN while `5.0 / 0.0` is inf -- the "
                    "b == 0 early return is what makes those differ",
                )
            )

        # THE PRECISION CASES. `_exact_value_check`, not the default pipeline:
        # a 1-ULP float32 error at these magnitudes is ~8e-8 relative, well
        # inside this harness's 1e-5 float32 rtol, so under the default
        # comparator these cases could not fail.
        for dtype_name, pairs in _DIV_PRECISION.items():
            a_t, a_c = pair_from_flat(
                torch_module, c_module, [a for a, _ in pairs], (len(pairs),), dtype_name
            )
            b_t, b_c = pair_from_flat(
                torch_module, c_module, [b for _, b in pairs], (len(pairs),), dtype_name
            )
            cases.append(
                Case(
                    name=f"div.Tensor_mode({dtype_name}, rounding_mode={mode!r}) "
                    "[computed in the tensor's own dtype, not f64]",
                    op=op,
                    run_torch=lambda a_t=a_t, b_t=b_t, m=mode: torch_call(
                        a_t, b_t, rounding_mode=m
                    ),
                    run_c=lambda a_c=a_c, b_c=b_c, m=mode: c_module._aten_dispatch(
                        op, a_c, b_c, rounding_mode=m
                    ),
                    value_check=_exact_value_check,
                    note="every pair here is one where computing in f64 and "
                    "narrowing once gives a different answer; the default "
                    "float32 tolerance would accept both",
                )
            )

        # Broadcasting, in both directions.
        a_t, a_c = pair_from_flat(torch_module, c_module, [7, -7, 6], (1, 3), "int64")
        b_t, b_c = pair_from_flat(torch_module, c_module, [3, -3], (2, 1), "int64")
        cases.append(
            Case(
                name=f"div.Tensor_mode((1,3) against (2,1), rounding_mode={mode!r}) [broadcast]",
                op=op,
                run_torch=lambda a_t=a_t, b_t=b_t, m=mode: torch_call(a_t, b_t, rounding_mode=m),
                run_c=lambda a_c=a_c, b_c=b_c, m=mode: c_module._aten_dispatch(
                    op, a_c, b_c, rounding_mode=m
                ),
                note="every sign combination appears in the (2,3) result",
            )
        )

        # Promotion follows torch.promote_types exactly (49 cells checked).
        for a_dt, b_dt in [
            ("int64", "int32"), ("int32", "float32"), ("float32", "float64"),
            ("float16", "float32"), ("float16", "bfloat16"), ("uint8", "int16"),
        ]:
            a_t, a_c = pair_from_flat(torch_module, c_module, [7], (1,), a_dt)
            b_t, b_c = pair_from_flat(torch_module, c_module, [3], (1,), b_dt)
            cases.append(
                Case(
                    name=f"div.Tensor_mode({a_dt} against {b_dt}, rounding_mode={mode!r}) "
                    "[promotion]",
                    op=op,
                    run_torch=lambda a_t=a_t, b_t=b_t, m=mode: torch_call(
                        a_t, b_t, rounding_mode=m
                    ),
                    run_c=lambda a_c=a_c, b_c=b_c, m=mode: c_module._aten_dispatch(
                        op, a_c, b_c, rounding_mode=m
                    ),
                    note="preserves the promoted integral dtype rather than "
                    "floating it the way rounding_mode=None does",
                )
            )

        # Bool on both sides: upstream refuses too, naming the kernel.
        a_t, a_c = pair_from_flat(torch_module, c_module, [True, False], (2,), "bool")
        b_t, b_c = pair_from_flat(torch_module, c_module, [True, True], (2,), "bool")
        cases.append(
            Case(
                name=f"div.Tensor_mode(bool, bool, rounding_mode={mode!r}) [upstream refuses too]",
                op=op,
                run_torch=lambda a_t=a_t, b_t=b_t, m=mode: torch_call(a_t, b_t, rounding_mode=m),
                run_c=lambda a_c=a_c, b_c=b_c, m=mode: c_module._aten_dispatch(
                    op, a_c, b_c, rounding_mode=m
                ),
                expect="both_error",
                note='upstream: \'"div_trunc_cpu"/"div_floor_cpu" not '
                "implemented for 'Bool'\"",
            )
        )

        # One zero divisor anywhere in an integral tensor raises.
        a_t, a_c = pair_from_flat(torch_module, c_module, [5, 6], (2,), "int64")
        b_t, b_c = pair_from_flat(torch_module, c_module, [3, 0], (2,), "int64")
        cases.append(
            Case(
                name=f"div.Tensor_mode(int64, [3, 0], rounding_mode={mode!r}) [one zero raises]",
                op=op,
                run_torch=lambda a_t=a_t, b_t=b_t, m=mode: torch_call(a_t, b_t, rounding_mode=m),
                run_c=lambda a_c=a_c, b_c=b_c, m=mode: c_module._aten_dispatch(
                    op, a_c, b_c, rounding_mode=m
                ),
                expect="both_error",
                note="RuntimeError('ZeroDivisionError'), not an inf in one lane",
            )
        )

        # Upstream's own length dependence, for the reduced floats only. This
        # shim answers upstream's n >= 2 value in both cases; at n == 1 upstream
        # computes in wider precision and the two disagree. Recorded so it fails
        # if upstream ever makes its two paths agree.
        for dtype_name in ("float16", "bfloat16"):
            # Keyed on the MODE as well as the dtype: a pair that diverges at
            # n == 1 under `floor` need not diverge under `trunc`, and picking
            # one per dtype gave a case that could not fail. Each of these four
            # was measured on both sides of n == 1.
            a, b = _DIV_N1_DIVERGENT[(dtype_name, mode)]
            a_t, a_c = pair_from_flat(torch_module, c_module, [a], (1,), dtype_name)
            b_t, b_c = pair_from_flat(torch_module, c_module, [b], (1,), dtype_name)
            cases.append(
                Case(
                    name=f"div.Tensor_mode({dtype_name} n=1, rounding_mode={mode!r}) "
                    "[upstream's one-element path uses wider precision]",
                    op=op,
                    run_torch=lambda a_t=a_t, b_t=b_t, m=mode: torch_call(
                        a_t, b_t, rounding_mode=m
                    ),
                    run_c=lambda a_c=a_c, b_c=b_c, m=mode: c_module._aten_dispatch(
                        op, a_c, b_c, rounding_mode=m
                    ),
                    expect="diverge",
                    note="upstream answers one value for a 1-element tensor and "
                    "another for the same operands in a 2-element tensor "
                    "(measured at n = 1, 2, 4, 7, 8, 16, 17, 32, 64, 100: only "
                    "n == 1 differs). This shim computes in the tensor's own "
                    "dtype, which is upstream's n >= 2 answer",
                )
            )

    # rounding_mode=None on the tensor form: true division, promoting.
    for dtype_name in ("int64", "float32"):
        a_t, a_c = pair_from_flat(torch_module, c_module, [7, -7, 6], (3,), dtype_name)
        b_t, b_c = pair_from_flat(torch_module, c_module, [3, 3, -3], (3,), dtype_name)
        cases.append(
            Case(
                name=f"div.Tensor_mode({dtype_name}, rounding_mode=None) [true division]",
                op=op,
                run_torch=lambda a_t=a_t, b_t=b_t: torch_call(a_t, b_t, rounding_mode=None),
                run_c=lambda a_c=a_c, b_c=b_c: c_module._aten_dispatch(
                    op, a_c, b_c, rounding_mode=None
                ),
                note="identical to aten.div.Tensor, which is what it delegates to",
            )
        )

    return cases


# --- aten.repeat.default ---------------------------------------------------
#
# The kernel docs/ARCH26.md §6/§8 found recurring across four of the six
# architectures (`deberta`, `deberta_v2`, `sew_d`, `sam3_video`), and the wall
# both DeBERTas landed on the moment `sqrt` was implemented.
#
# `repeat` is *tiling*, not broadcasting, and the difference is what this
# builder is for. `expand` produces a view whose strides are zero; `repeat`
# materialises a copy. The cases below cover the three places an
# implementation goes wrong:
#
#   * **`len(repeats) > rank`** -- the tensor gains leading dimensions.
#     `[1,2,3].repeat(2, 3)` is `(2, 9)`, not `(2, 3, 3)`: the *last* repeat
#     multiplies the existing dimension and the earlier ones are new.
#   * **a repeat of 0** -- upstream produces a genuinely empty dimension
#     (`[1,2,3].repeat(0)` is `(0,)`). An implementation that loops
#     `for r in repeats { if r > 1 { concat } }` -- which is candle's own
#     `Tensor::repeat` -- silently treats 0 as 1 and returns the input.
#   * **a non-contiguous input** -- `repeat` reads in logical order, so a
#     transposed input must be tiled by its logical layout and not by its
#     storage.
#
# dtype is passed through unchanged for every dtype including `bool`, which is
# measured rather than assumed: `repeat` is a data movement and does not
# promote.

_REPEAT_DTYPES = [
    "float64", "float32", "float16", "bfloat16",
    "int64", "int32", "int16", "uint8", "bool",
]

# (input flat, input shape, repeats, note)
_REPEAT_SHAPES: list[tuple[list, tuple, list, str]] = [
    ([1, 2, 3], (3,), [2], "1-D, same rank"),
    ([1, 2, 3], (3,), [1], "1-D, repeat of 1 -- must still be a copy"),
    ([1, 2, 3], (3,), [2, 3], "1-D -> 2-D: the LAST repeat multiplies, the first is new"),
    ([1, 2, 3], (3,), [2, 3, 4], "1-D -> 3-D"),
    ([1, 2, 3, 4], (2, 2), [2, 3], "2-D, same rank"),
    ([1, 2, 3, 4], (2, 2), [1, 1], "2-D, all ones -- must still be a copy"),
    ([1, 2, 3, 4], (2, 2), [2, 1, 3], "2-D -> 3-D"),
    ([1, 2, 3, 4, 5, 6], (2, 3), [3, 2], "2-D, non-square"),
    ([5], (), [3], "0-D -> 1-D"),
    ([5], (), [2, 2], "0-D -> 2-D"),
    ([5], (), [], "0-D with an empty repeat list stays 0-D"),
    ([1, 2, 3], (3,), [0], "repeat of 0 -> an empty dimension, NOT a no-op"),
    ([1, 2, 3, 4], (2, 2), [0, 2], "repeat of 0 on the leading axis"),
    ([1, 2, 3, 4], (2, 2), [2, 0], "repeat of 0 on the trailing axis"),
    ([], (0, 3), [2, 2], "an already-empty input"),
]


def repeat_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.repeat.default"
    cases: list[Case] = []

    for dtype_name in _REPEAT_DTYPES:
        for flat, shape, repeats, note in _REPEAT_SHAPES:
            src = [bool(v) for v in flat] if dtype_name == "bool" else flat
            a_t, a_c = pair_from_flat(torch_module, c_module, src, shape, dtype_name)
            cases.append(
                Case(
                    name=f"repeat(dtype={dtype_name}, shape={shape}, repeats={repeats}) [{note}]",
                    op=op,
                    run_torch=lambda a_t=a_t, r=repeats: torch_call(a_t, r),
                    run_c=lambda a_c=a_c, r=repeats: c_module._aten_dispatch(op, a_c, r),
                    note=note,
                )
            )

    # A transposed input: `repeat` must tile the logical layout, not the
    # storage. `arange(6).reshape(2, 3).t()` is `(3, 2)` with strides `(1, 3)`.
    base_t = torch_module.arange(6, dtype=torch_module.float32).reshape(2, 3).t()
    base_c = c_module._aten_dispatch(
        "aten.t.default",
        c_module._aten_dispatch(
            "aten.view.default",
            c_module._tensor_from_flat([0.0, 1.0, 2.0, 3.0, 4.0, 5.0], [6], c_module.float32),
            [2, 3],
        ),
    )
    for repeats in ([2, 1], [1, 2], [2, 3], [2, 1, 1]):
        cases.append(
            Case(
                name=f"repeat(non-contiguous (3,2) transpose, repeats={repeats})",
                op=op,
                run_torch=lambda t=base_t, r=repeats: torch_call(t, r),
                run_c=lambda c=base_c, r=repeats: c_module._aten_dispatch(op, c, r),
                note="strides (1, 3) -- tiled by logical order, not by storage",
            )
        )

    # Refusals, both upstream's, both with upstream's own wording.
    a_t, a_c = pair_from_flat(torch_module, c_module, [1.0, 2.0, 3.0, 4.0], (2, 2), "float32")
    cases.append(
        Case(
            name="repeat(rank 2, repeats=[2]) [fewer repeats than dimensions]",
            op=op,
            run_torch=lambda a_t=a_t: torch_call(a_t, [2]),
            run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, [2]),
            expect="both_error",
            note="upstream: 'Number of dimensions of repeat dims can not be smaller "
            "than number of dimensions of tensor'",
        )
    )
    for repeats in ([-1, 2], [2, -1]):
        cases.append(
            Case(
                name=f"repeat(rank 2, repeats={repeats}) [negative repeat]",
                op=op,
                run_torch=lambda a_t=a_t, r=repeats: torch_call(a_t, r),
                run_c=lambda a_c=a_c, r=repeats: c_module._aten_dispatch(op, a_c, r),
                expect="both_error",
                note="upstream: 'Trying to create tensor with negative dimension'",
            )
        )

    return cases


# --- aten.lift_fresh.default (backs `torch.tensor(...)` construction) --------
#
# `torch.tensor([...])` -- the 13th name docs/C_SURFACE.md traced -- does
# not dispatch through a single clean "construct from Python data" aten op;
# tracing it with a TorchDispatchMode shows it going through
# `aten.lift_fresh.default(Tensor self) -> Tensor`, an identity-shaped op
# that marks an already-built tensor as a fresh autograd leaf. This matches
# build.py's own docstring on `_tensor_from_flat`: "there is no aten op yet
# that takes a Python list of numbers" -- the list-to-tensor step itself is
# scaffolding outside the aten dispatch surface this harness compares.
# `aten.lift_fresh.default` is the op name most likely to show up in
# `_aten_implemented()` for the "tensor" entry point; this builder checks
# it is a true identity (same dtype/shape/values as its input) across the
# dtypes/shapes this harness already exercises elsewhere. If rust/torch_c
# ends up exposing tensor construction under a different name, this
# builder simply stays pending -- see the module note above.

_LIFT_FRESH_DTYPES = ["float64", "float32", "float16", "bfloat16", "int64", "int32", "uint8"]


def lift_fresh_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.lift_fresh.default"
    cases: list[Case] = []

    for dtype_name in _LIFT_FRESH_DTYPES:
        for flat, shape in [([0], ()), ([1, 2, 3], (3,)), ([1, 2, 3, 4], (2, 2))]:
            a_t, a_c = pair_from_flat(torch_module, c_module, flat, shape, dtype_name)
            cases.append(
                Case(
                    name=f"lift_fresh(dtype={dtype_name}, shape={shape}) [identity]",
                    op=op,
                    run_torch=lambda a_t=a_t: torch_call(a_t),
                    run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c),
                    note="backs torch.tensor(...) construction -- see note above",
                )
            )

    return cases


# --- pre-seeded case builders for the ops backing TensorBase's 50 --------
# actually-used members (docs/C_SURFACE.md §4)
#
# docs/C_SURFACE.md traced a small Llama forward+generate() against real
# upstream torch (torch 2.13.0) and found 50 `TensorBase` members actually
# get accessed via a `torch.Tensor` instance -- 49 real API names plus the
# `__class__` bookkeeping dunder (not a real API, not covered here). Another
# change is implementing the rust/torch_c side of these; the builders below
# are written ahead of that landing, exactly like the 16 pre-seeded above,
# so coverage activates the moment each op appears in `_aten_implemented()`
# -- see the module note above `arange_default_cases` for how `compare.py`
# keeps an unimplemented op's builder inert (PENDING, not FAIL) until then.
#
# **Methods are not functions -- overloads were measured, not guessed.**
# `x * 2`, `x + 2`, `x - 2`, `x / 2` (dunder-operator paths) were checked
# with a real `TorchDispatchMode` probe against torch 2.13.0 before writing
# any of this, because the difference between an op's overloads takes
# different arguments and there is no way to guess it correctly from the
# method name alone (see the `full`/`add`/`mm` docstring above). Two results
# were surprising enough to call out explicitly:
#
#   - `x * 2`, `x + 2`, `x - 2`, `x / 2` all dispatch through the *.Tensor*
#     overload (`mul.Tensor`, `add.Tensor`, `sub.Tensor`, `div.Tensor`) --
#     the Python scalar is silently wrapped into a 0-d tensor by the dunder
#     before the dispatcher ever sees it. There is no reachable `.Scalar`
#     overload for these dunders.
#   - `x & True`, `x | True`, `x == 2`, `x < 2`, `x.ne(2)` do the opposite:
#     the Python scalar stays a Scalar and dispatches to the `.Scalar`
#     overload (`bitwise_and.Scalar`, `bitwise_or.Scalar`, `eq.Scalar`,
#     `lt.Scalar`, `ne.Scalar`). Same "dunder/method given a Python number"
#     shape as the arithmetic ops above, opposite dispatch behaviour --
#     each family was probed independently rather than assumed to match.
#
# `__matmul__` needs no new builder here: the probe showed it dispatches to
# `aten.mm.default`, already covered by `mm_cases` above.
#
# **Nine of the 50 names never reach the ATen dispatcher at all.** `device`,
# `dim`, `dtype`, `grad_fn`, `ndim`, `numel`, `requires_grad`,
# `requires_grad_`, `shape`, `size` were probed the same way (called inside
# a `TorchDispatchMode`) and produced zero recorded dispatcher calls --
# they read (or, for `requires_grad_`, mutate) metadata already sitting on
# the TensorImpl without going through the aten op dispatch this harness
# compares. There is no aten overload for `_aten_dispatch` to be given for
# these, so they intentionally have no case builder; this is a property of
# the harness's aten-op-granularity design, not an oversight.
#
# **In-place methods compare differently.** `fill_`, `copy_`, `normal_`,
# `uniform_` mutate their operand rather than returning a fresh value.
# Structurally this needs no different harness machinery than any other
# case -- `torch.ops.aten.<op>_.<overload>` returns the same (now mutated)
# object, so the existing run_torch/run_c/compare pipeline already compares
# the *result* of an in-place call correctly -- but it does mean every
# in-place case here builds a **fresh** operand pair per case (never shares
# one tensor across two cases), or an earlier case's mutation would leak
# into a later one that expects a clean starting value. `normal_` and
# `uniform_` still use `Case.value_check` instead of the default pipeline,
# but no longer because they are unmatchable -- see their builders below, and
# `_rng_stream_check`, for what they compare now.
#
# `contiguous()` needs no separate builder: on a non-contiguous input it
# dispatches to `aten.clone.default`, the same op `clone()` uses (probed);
# on an already-contiguous input it is a no-op that never reaches the
# dispatcher, so there is nothing there to compare either.
#
# `reshape()` needs no separate builder for the same reason: on a
# contiguous input it dispatches to `aten.view.default` (the same op
# `view()` uses, see `view_cases`); on a non-contiguous input it instead
# dispatches to `aten.clone.default` + `aten._unsafe_view.default` -- a
# second op this harness's single-op-per-case design does not attempt to
# chain, matching the same granularity limitation already documented for
# `contiguous()`.


def _binary_tensor_case(
    torch_module, c_module, op, torch_call, dtype_name, a_flat, a_shape, b_flat, b_shape, note, kwargs=None
) -> Case:
    kwargs = kwargs or {}
    a_t, a_c = pair_from_flat(torch_module, c_module, a_flat, a_shape, dtype_name)
    b_t, b_c = pair_from_flat(torch_module, c_module, b_flat, b_shape, dtype_name)
    short = op.split(".", 2)[1]
    name = f"{short}(dtype={dtype_name}, a_shape={a_shape}, b_shape={b_shape}) [{note}]"
    return Case(
        name=name,
        op=op,
        run_torch=lambda: torch_call(a_t, b_t, **kwargs),
        run_c=lambda: c_module._aten_dispatch(op, a_c, b_c, **kwargs),
        note=note,
    )


def _binary_scalar_case(torch_module, c_module, op, torch_call, dtype_name, a_flat, a_shape, scalar, note) -> Case:
    a_t, a_c = pair_from_flat(torch_module, c_module, a_flat, a_shape, dtype_name)
    short = op.split(".", 2)[1]
    name = f"{short}(dtype={dtype_name}, a_shape={a_shape}, scalar={scalar!r}) [{note}]"
    return Case(
        name=name,
        op=op,
        run_torch=lambda: torch_call(a_t, scalar),
        run_c=lambda: c_module._aten_dispatch(op, a_c, scalar),
        note=note,
    )


def _unary_case(torch_module, c_module, op, torch_call, dtype_name, flat, shape, note, kwargs=None) -> Case:
    kwargs = kwargs or {}
    a_t, a_c = pair_from_flat(torch_module, c_module, flat, shape, dtype_name)
    short = op.split(".", 2)[1]
    name = f"{short}(dtype={dtype_name}, shape={shape}) [{note}]"
    return Case(
        name=name,
        op=op,
        run_torch=lambda: torch_call(a_t, **kwargs),
        run_c=lambda: c_module._aten_dispatch(op, a_c, **kwargs),
        note=note,
    )


_ELEMENTWISE_SCENARIOS: list[dict] = [
    dict(a_flat=[1, 2, 3, 4], a_shape=(2, 2), b_flat=[5, 6, 7, 8], b_shape=(2, 2), note="elementwise"),
    dict(a_flat=[7], a_shape=(), b_flat=[1, 2, 3, 4], b_shape=(2, 2), note="scalar (0-d) broadcast"),
    dict(a_flat=[1, 2, 3, 4, 5, 6], a_shape=(2, 3), b_flat=[10, 20, 30], b_shape=(3,), note="row broadcast"),
]


def _elementwise_boundary_scenario(big) -> dict:
    return dict(
        a_flat=[0, -5, big, -big],
        a_shape=(2, 2),
        b_flat=[0, 5, -big, big],
        b_shape=(2, 2),
        note="boundary values (0/neg/large)",
    )


# --- aten.sub.Tensor -------------------------------------------------------
# `__sub__` -- probe confirmed the `.Tensor` overload even for `x - 2`
# (scalar wrapped to a 0-d tensor), same shape as `add.Tensor` above, so
# this reuses `add_cases`' own scenario generators verbatim.


def sub_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.sub.Tensor"
    cases: list[Case] = []

    for dtype_name in _FLOAT_ADD_DTYPES:
        for scenario in _float_add_scenarios(_FLOAT_ADD_MAGNITUDE[dtype_name]):
            a_t, a_c = pair_from_flat(torch_module, c_module, scenario["a_flat"], scenario["a_shape"], dtype_name)
            b_t, b_c = pair_from_flat(torch_module, c_module, scenario["b_flat"], scenario["b_shape"], dtype_name)
            alpha = scenario["alpha"]
            kwargs = {} if alpha is None else {"alpha": alpha}
            name = (
                f"sub(dtype={dtype_name}, a_shape={scenario['a_shape']}, b_shape={scenario['b_shape']}, "
                f"alpha={alpha}) [{scenario['note']}]"
            )
            cases.append(
                Case(
                    name=name,
                    op=op,
                    run_torch=lambda a_t=a_t, b_t=b_t, kwargs=kwargs: torch_call(a_t, b_t, **kwargs),
                    run_c=lambda a_c=a_c, b_c=b_c, kwargs=kwargs: c_module._aten_dispatch(op, a_c, b_c, **kwargs),
                )
            )

    for dtype_name, big in [("int64", 10**9), ("int32", 10**6), ("int16", 1000)]:
        for scenario in _int_add_scenarios_signed(big):
            a_t, a_c = pair_from_flat(torch_module, c_module, scenario["a_flat"], scenario["a_shape"], dtype_name)
            b_t, b_c = pair_from_flat(torch_module, c_module, scenario["b_flat"], scenario["b_shape"], dtype_name)
            alpha = scenario["alpha"]
            kwargs = {} if alpha is None else {"alpha": alpha}
            name = (
                f"sub(dtype={dtype_name}, a_shape={scenario['a_shape']}, b_shape={scenario['b_shape']}, "
                f"alpha={alpha}) [{scenario['note']}]"
            )
            cases.append(
                Case(
                    name=name,
                    op=op,
                    run_torch=lambda a_t=a_t, b_t=b_t, kwargs=kwargs: torch_call(a_t, b_t, **kwargs),
                    run_c=lambda a_c=a_c, b_c=b_c, kwargs=kwargs: c_module._aten_dispatch(op, a_c, b_c, **kwargs),
                )
            )

    return cases


# --- aten.mul.Tensor / aten.div.Tensor -------------------------------------
# `__mul__`/`__truediv__` -- same probe result as sub: `.Tensor` overload
# even for a Python-scalar RHS, no `.Scalar` overload reachable from these
# dunders.

_MUL_DIV_FLOAT_DTYPES = ["float64", "float32", "float16", "bfloat16"]
_MUL_DIV_INT_DTYPES = ["int64", "int32", "int16"]
_MUL_MAGNITUDE = {
    "float64": 1e3,
    "float32": 1e3,
    "float16": 10.0,
    "bfloat16": 100.0,
    "int64": 1000,
    "int32": 100,
    "int16": 50,
}


def mul_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.mul.Tensor"
    cases: list[Case] = []
    for dtype_name in _MUL_DIV_FLOAT_DTYPES + _MUL_DIV_INT_DTYPES:
        big = _MUL_MAGNITUDE[dtype_name]
        for sc in _ELEMENTWISE_SCENARIOS + [_elementwise_boundary_scenario(big)]:
            cases.append(
                _binary_tensor_case(
                    torch_module, c_module, op, torch_call, dtype_name,
                    sc["a_flat"], sc["a_shape"], sc["b_flat"], sc["b_shape"], sc["note"],
                )
            )
    # uint8 wraparound -- both sides should wrap identically (modular
    # arithmetic), same precedent as add_cases' uint8 wraparound case.
    cases.append(
        _binary_tensor_case(
            torch_module, c_module, op, torch_call, "uint8",
            [200, 200], (2,), [100, 2], (2,), "uint8 overflow wraps (both sides modular)",
        )
    )
    cases.extend(_mul_promotion_cases(torch_module, c_module, torch_call))
    return cases


# --- mul.Tensor dtype promotion ---------------------------------------------
#
# `mul.Tensor` promotes; `add`/`sub`/`div` in this shim still refuse through
# `same_dtype`. That split is not tidiness, it is the "no unmeasured
# implementation" rule (docs/E2E_REAL.md §1.2): `generate()` on a real
# pretrained model reaches exactly one promoting multiply and no promoting
# add. transformers' `_prepare_attention_mask_for_generation` computes
#
#     attention_mask_from_padding * can_infer_attention_mask
#         + default_attention_mask * ~can_infer_attention_mask
#
# where each `*` has an `int64` left operand (`.long()`) and a 0-D `bool`
# right one (`.any()`), and the `+` joining them is int64 with int64. Read
# off the running model, not the source: a `TorchDispatchMode` over
# `model.generate` reports `aten.mul.Tensor(int64, bool)` and
# `aten.add.Tensor(int64, int64)`.
#
# The table is `torch.promote_types` over every dtype `TorchDType::storage()`
# can hold, measured on 2.13.0 and separately checked cell by cell against
# `mul.Tensor`'s OWN result dtype -- they agree in every cell where both are
# defined, which is why one rule can serve both. Two rows are the ones a
# plausible-looking shortcut gets wrong:
#
#     int64 x float16    -> float16    an integral operand never widens a float
#     float16 x bfloat16 -> float32    two reduced floats promote OUT, not to
#                                      either input
#
# `uint32` mixed with `bool` or a signed integer is a real UPSTREAM refusal
# ("Promotion for uint16, uint32, uint64 types is not supported"), not a shim
# gap, so those cells are `both_error` -- a shim that promoted them would
# answer where torch raises.

_PROMOTE_DTYPES = ["bool", "uint8", "uint32", "int16", "int32", "int64",
                   "float16", "bfloat16", "float32", "float64"]

# The cells upstream refuses. Measured, not derived: every other cell of the
# 10x10 is expected to compute, and compare.py checks dtype, shape and value
# against upstream directly rather than against any table written here.
_PROMOTE_FLOATS = {"float16", "bfloat16", "float32", "float64"}
_PROMOTE_REFUSED = {
    (a, b)
    for a in _PROMOTE_DTYPES
    for b in _PROMOTE_DTYPES
    if "uint32" in (a, b) and a != b and not ({a, b} & _PROMOTE_FLOATS)
}

# The rows worth naming in the report, so the rule is legible without running
# the harness. Checked by the sweep below like every other cell; listed here
# only so a reader sees which way each one goes.
_PROMOTE_NOTABLE = {
    ("int64", "bool"): "int64 -- the cell generate() actually needs",
    ("bool", "int64"): "int64 -- and it is symmetric",
    ("bool", "bool"): "bool -- product IS logical and under the 0/1 invariant",
    ("int64", "float16"): "float16 -- an INTEGRAL operand never widens a float",
    ("float16", "bfloat16"): "float32 -- two reduced floats promote OUT",
    ("uint8", "int16"): "int16 -- unsigned meets signed",
    ("float32", "float64"): "float64 -- the ordinary widening",
    ("bool", "float32"): "float32 -- bool is the bottom of the lattice",
}


def _promote_flat(dtype_name: str, which: str) -> list[int]:
    """Small exact operands, representable in every dtype of the sweep.

    Deliberately not `_deterministic`: `bool` can only hold 0/1 and `uint8`
    only non-negatives, and the point of these cases is the dtype of the
    result, so the values are chosen to be exact everywhere and to make a
    *wrong* promotion visible in the values too -- `bool` operands carry a
    zero, so reading them as anything but 0/1 changes the product.
    """
    if dtype_name == "bool":
        return [1, 0, 1, 1] if which == "a" else [1, 1, 0, 1]
    return [1, 2, 3, 4] if which == "a" else [3, 0, 2, 1]


def _mul_promotion_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.mul.Tensor"
    cases: list[Case] = []
    for a_dtype in _PROMOTE_DTYPES:
        for b_dtype in _PROMOTE_DTYPES:
            refused = (a_dtype, b_dtype) in _PROMOTE_REFUSED
            note = _PROMOTE_NOTABLE.get((a_dtype, b_dtype), "")
            if refused:
                note = ("upstream refuses: no promotion for uint16/uint32/uint64 -- "
                        "the shim refuses by name rather than answering")
            a_t, a_c = pair_from_flat(
                torch_module, c_module, _promote_flat(a_dtype, "a"), (2, 2), a_dtype
            )
            b_t, b_c = pair_from_flat(
                torch_module, c_module, _promote_flat(b_dtype, "b"), (2, 2), b_dtype
            )
            cases.append(
                Case(
                    name=f"mul.Tensor(promote {a_dtype} x {b_dtype})"
                         + (f" [{note}]" if note else ""),
                    op=op,
                    run_torch=lambda a_t=a_t, b_t=b_t: torch_call(a_t, b_t),
                    run_c=lambda a_c=a_c, b_c=b_c: c_module._aten_dispatch(op, a_c, b_c),
                    expect="both_error" if refused else "match",
                    note=note,
                )
            )

    # The call site verbatim, at its real shape: an `int64` (1, N) mask times
    # a 0-D `bool`. The 0-D right operand is what makes this more than another
    # cell of the sweep -- it broadcasts AND promotes at once, and a kernel
    # that promoted by casting the result back to the *left* operand's shape
    # would still pass the (2,2) x (2,2) cells.
    for flag, note in [(1, "can_infer=True -> the padding mask survives"),
                       (0, "can_infer=False -> the padding mask is zeroed")]:
        mask_t, mask_c = pair_from_flat(
            torch_module, c_module, [1, 1, 0, 1], (1, 4), "int64"
        )
        flag_t, flag_c = pair_from_flat(torch_module, c_module, [flag], (), "bool")
        cases.append(
            Case(
                name=f"mul.Tensor(int64 (1,4) x 0-D bool={bool(flag)}) [{note}]",
                op=op,
                run_torch=lambda mask_t=mask_t, flag_t=flag_t: torch_call(mask_t, flag_t),
                run_c=lambda mask_c=mask_c, flag_c=flag_c: c_module._aten_dispatch(
                    op, mask_c, flag_c
                ),
                note="_prepare_attention_mask_for_generation verbatim -- " + note,
            )
        )
    return cases


def div_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.div.Tensor"
    cases: list[Case] = []
    for dtype_name in _MUL_DIV_FLOAT_DTYPES + _MUL_DIV_INT_DTYPES:
        for sc in _ELEMENTWISE_SCENARIOS:
            cases.append(
                _binary_tensor_case(
                    torch_module, c_module, op, torch_call, dtype_name,
                    sc["a_flat"], sc["a_shape"], sc["b_flat"], sc["b_shape"], sc["note"],
                )
            )
    # Division by zero: `div.Tensor` is always true division (confirmed by
    # probe -- it never does integer floor division, even for integer
    # inputs, and promotes to a floating dtype), and IEEE-754 makes 0
    # division well-defined (inf/-inf/nan) rather than an error. Both sides
    # are expected to *compute* the same pattern, not refuse.
    for dtype_name in _MUL_DIV_FLOAT_DTYPES:
        cases.append(
            _binary_tensor_case(
                torch_module, c_module, op, torch_call, dtype_name,
                [1.0, -1.0, 0.0, 5.0], (2, 2), [0.0, 0.0, 0.0, 2.0], (2, 2),
                "division by zero -> inf/-inf/nan, not an error",
            )
        )
    cases.extend(_div_promotion_cases(torch_module, c_module, torch_call))
    return cases


def _div_promotion_cases(torch_module, c_module, torch_call) -> list[Case]:
    """`div.Tensor` promotes its operands too, since docs/KERNELS26.md §23.

    `sam3_video`'s SAM3 detector divides a `float32` grid by an `int64` stride
    and stopped on `aten.div.Tensor: dtype promotion not implemented ...
    float32 vs int64`. That is not a missing kernel and not a missing name --
    it is `same_dtype` refusing a mixed pair -- so the fix is the condition
    that already lets `mul` promote, extended to `div`.

    The **whole 10x10 sweep** is re-run here rather than only the cell
    `sam3_video` needs, because `div`'s result dtype is not `mul`'s: true
    division floats an integral pair, so `int64 / int64` is `float32` where
    `int64 * int64` is `int64`. A promotion rule copied from `mul` and a
    result rule copied from `mul` are two different mistakes, and only the
    full grid separates the second one.

    `add` and `sub` are deliberately NOT promoted and there are cases below
    asserting they still refuse -- so this change is visible as a change to
    two of the four and not to all four.
    """
    op = "aten.div.Tensor"
    cases: list[Case] = []
    for a_dtype in _PROMOTE_DTYPES:
        for b_dtype in _PROMOTE_DTYPES:
            refused = (a_dtype, b_dtype) in _PROMOTE_REFUSED
            # `bool / bool` is the one cell where the shim declines and
            # upstream does not, and it is a *pre-existing* refusal this
            # change walks into rather than one it introduces: `arith_tag`
            # refuses `bool` arithmetic outright (BOOL.md §2.2 -- `bool`
            # operators are logical in torch, and `True / True` being
            # `float32 1.0` is the one arithmetic exception). `mul`'s own
            # sweep never sees it because `bool * bool` stays `bool` and IS
            # logical-and. Watched as `c_error`, so the day `arith_tag` gains
            # a bool row this fails and gets promoted.
            bool_pair = a_dtype == "bool" and b_dtype == "bool"
            expect = "both_error" if refused else ("c_error" if bool_pair else "match")
            note = ("bool/bool: upstream gives float32; the shim refuses bool "
                    "arithmetic, BOOL.md §2.2" if bool_pair else
                    "true division floats the result; the OPERAND promotion is mul's rule")
            a_t, a_c = pair_from_flat(
                torch_module, c_module, _promote_flat(a_dtype, "a"), (2, 2), a_dtype)
            b_t, b_c = pair_from_flat(
                torch_module, c_module, _promote_flat(b_dtype, "b"), (2, 2), b_dtype)
            cases.append(
                Case(
                    name=f"div.Tensor(promote {a_dtype} / {b_dtype})",
                    op=op,
                    run_torch=lambda a_t=a_t, b_t=b_t: torch_call(a_t, b_t),
                    run_c=lambda a_c=a_c, b_c=b_c: c_module._aten_dispatch(op, a_c, b_c),
                    expect=expect,
                    note=note,
                )
            )
    # `sam3_video`'s own pairing, at a shape where the right operand is 0-D --
    # so it broadcasts and promotes at once.
    grid_t, grid_c = pair_from_flat(
        torch_module, c_module, [0.0, 8.0, 16.0, 24.0], (1, 4), "float32")
    stride_t, stride_c = pair_from_flat(torch_module, c_module, [8], (), "int64")
    cases.append(
        Case(
            name="div.Tensor(float32 (1,4) / 0-D int64) [sam3_video's own pairing]",
            op=op,
            run_torch=lambda: torch_call(grid_t, stride_t),
            run_c=lambda: c_module._aten_dispatch(op, grid_c, stride_c),
            note="the SAM3 detector divides a float32 grid by an int64 stride",
        )
    )
    # ...and the two that still refuse, so the split is asserted rather than
    # implied. `c_error`: upstream computes both, and the day either gains a
    # promoting kernel this fails and gets promoted to `match`.
    for other_op, torch_name in (("aten.add.Tensor", "add"), ("aten.sub.Tensor", "sub")):
        l_t, l_c = pair_from_flat(
            torch_module, c_module, [1.0, 2.0, 3.0, 4.0], (2, 2), "float32")
        r_t, r_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (2, 2), "int64")
        cases.append(
            Case(
                name=f"{other_op}(float32, int64) [still refused -- only mul and div promote]",
                op=op,
                run_torch=lambda l_t=l_t, r_t=r_t, n=torch_name: getattr(
                    torch_module.ops.aten, n).Tensor(l_t, r_t),
                run_c=lambda l_c=l_c, r_c=r_c, o=other_op: c_module._aten_dispatch(
                    o, l_c, r_c),
                expect="c_error",
                note="docs/BIND.md §9: the split records which callers were measured, "
                     "not a principle -- nothing in the sweep adds a mixed pair",
            )
        )
    return cases


# --- aten.bitwise_and.{Tensor,Scalar} / aten.bitwise_or.{Tensor,Scalar} ----
# `__and__`/`__or__` -- probe confirmed these *do* keep a Python scalar as a
# Scalar (unlike the arithmetic dunders above), so both overloads are
# reachable and both get builders.
#
# **No `dtype=bool` scenario here (or in bitwise_not/select/slice/clone/
# local_scalar_dense/any below).** `_C`'s own `_tensor_from_flat` refuses to
# construct a bool tensor directly (found while smoke-testing these
# builders against real torch): `NotImplementedError: _tensor_from_flat:
# torch.bool is not accepted here -- a bool tensor must come from an op
# that guarantees 0/1 bytes (BOOL.md §6.3)`. That refusal happens at
# case-*list*-construction time (`cases = builder(...)` in compare.py's
# `run()`), which is not wrapped in a try/except the way a single case's
# run_torch/run_c is -- so an eager `pair_from_flat(..., "bool")` call in a
# module-level scope here would crash the *entire* harness run the moment
# this op lands in `_aten_implemented()`, not just fail one case. Real,
# attention-mask-flavoured bool coverage is still int-dtype-representative
# via `_BITWISE_INT_DTYPES` (bitwise ops are defined identically on bool
# and integer types), so nothing is silently lost by leaving bool out here.
# `masked_fill_cases` and `index_tensor_cases` below need an actual bool
# mask (schema-mandated), so those defer construction into the run_torch/
# run_c lambdas instead of dropping it -- see their module notes.

_BITWISE_INT_DTYPES = ["int64", "int32", "int16", "uint8"]


def bitwise_and_tensor_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.bitwise_and.Tensor"
    cases: list[Case] = []
    for dtype_name in _BITWISE_INT_DTYPES:
        cases.append(
            _binary_tensor_case(
                torch_module, c_module, op, torch_call, dtype_name,
                [0b1100, 0b1010, 0b1111, 0], (2, 2), [0b1010, 0b0110, 0b0000, 0b1111], (2, 2), "elementwise AND",
            )
        )

    # --- dtype promotion -----------------------------------------------------
    #
    # The second promoting op, found the same way as the first: by running
    # `generate()` and reading where it stopped. Past
    # `_prepare_attention_mask_for_generation` (which needed `mul.Tensor`),
    # the sampling loop's own stopping condition is
    #
    #     unfinished_sequences = unfinished_sequences & ~stopping_criteria(...)
    #
    # at `generation/utils.py:2936` -- `int64 & bool`, because
    # `unfinished_sequences` is `torch.ones(..., dtype=torch.long)` and the
    # criteria return `bool`.
    #
    # `bitwise_and.Tensor` and `bitwise_or.Tensor` were BOTH re-measured
    # against `torch.promote_types` over the storable dtypes and agree with
    # it in every cell, so the same table serves both. Only `and` is wired,
    # because only `and` has a measured caller; the `or` cases below stay
    # `c_error` and say why, so the day a caller turns up the gap is already
    # written down rather than rediscovered.
    #
    # A floating operand is refused by UPSTREAM here, not by the shim --
    # `"bitwise_and_cpu" not implemented for 'Float'` -- so promotion
    # reaching a float dtype has to end in a refusal on both sides rather
    # than in an answer.
    for a_dtype, b_dtype, note in [
        ("int64", "bool", "int64 -- the cell generate() actually needs"),
        ("bool", "int64", "int64 -- and it is symmetric"),
        ("uint8", "int16", "int16 -- unsigned meets signed"),
        ("int16", "int64", "int64 -- the ordinary widening"),
        ("bool", "uint8", "uint8 -- bool is the bottom of the lattice here too"),
    ]:
        a_t, a_c = pair_from_flat(
            torch_module, c_module, _promote_flat(a_dtype, "a"), (2, 2), a_dtype
        )
        b_t, b_c = pair_from_flat(
            torch_module, c_module, _promote_flat(b_dtype, "b"), (2, 2), b_dtype
        )
        cases.append(
            Case(
                name=f"bitwise_and.Tensor(promote {a_dtype} x {b_dtype}) [{note}]",
                op=op,
                run_torch=lambda a_t=a_t, b_t=b_t: torch_call(a_t, b_t),
                run_c=lambda a_c=a_c, b_c=b_c: c_module._aten_dispatch(op, a_c, b_c),
                note=note,
            )
        )
    for a_dtype, b_dtype, note in [
        ("float32", "bool", "upstream: \"bitwise_and_cpu\" not implemented for 'Float'"),
        ("int64", "uint32", "upstream has no promotion for uint32 against a signed int"),
    ]:
        a_t, a_c = pair_from_flat(
            torch_module, c_module, _promote_flat(a_dtype, "a"), (2, 2), a_dtype
        )
        b_t, b_c = pair_from_flat(
            torch_module, c_module, _promote_flat(b_dtype, "b"), (2, 2), b_dtype
        )
        cases.append(
            Case(
                name=f"bitwise_and.Tensor(promote {a_dtype} x {b_dtype} -- refused by both)",
                op=op,
                run_torch=lambda a_t=a_t, b_t=b_t: torch_call(a_t, b_t),
                run_c=lambda a_c=a_c, b_c=b_c: c_module._aten_dispatch(op, a_c, b_c),
                expect="both_error",
                note=note,
            )
        )

    # The call site verbatim: a 1-element `int64` counter ANDed with a `bool`
    # from the stopping criteria.
    for flag, note in [(1, "not finished -- the counter survives"),
                       (0, "finished -- the counter is cleared")]:
        uf_t, uf_c = pair_from_flat(torch_module, c_module, [1], (1,), "int64")
        st_t, st_c = pair_from_flat(torch_module, c_module, [flag], (1,), "bool")
        cases.append(
            Case(
                name=f"bitwise_and.Tensor(int64 counter & bool={bool(flag)}) [{note}]",
                op=op,
                run_torch=lambda uf_t=uf_t, st_t=st_t: torch_call(uf_t, st_t),
                run_c=lambda uf_c=uf_c, st_c=st_c: c_module._aten_dispatch(op, uf_c, st_c),
                note="generation/utils.py:2936 verbatim -- " + note,
            )
        )
    return cases


def bitwise_and_scalar_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.bitwise_and.Scalar"
    cases: list[Case] = []
    for dtype_name in _BITWISE_INT_DTYPES:
        cases.append(
            _binary_scalar_case(
                torch_module, c_module, op, torch_call, dtype_name,
                [0b1100, 0b1010, 0b1111, 0], (2, 2), 0b1010, "x & 0b1010",
            )
        )
    return cases


def bitwise_or_tensor_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.bitwise_or.Tensor"
    cases: list[Case] = []
    for dtype_name in _BITWISE_INT_DTYPES:
        cases.append(
            _binary_tensor_case(
                torch_module, c_module, op, torch_call, dtype_name,
                [0b1100, 0b1010, 0b0000, 0], (2, 2), [0b0010, 0b0100, 0b1111, 0b0001], (2, 2), "elementwise OR",
            )
        )

    # The deliberate asymmetry with `bitwise_and`, pinned so it stays
    # deliberate. `or` was measured to follow the SAME promotion table as
    # `and` -- both agree with `torch.promote_types` in every storable cell --
    # and it is left refusing only because no measured caller reaches it
    # (docs/E2E_REAL.md §1.2). If a caller turns up, wiring it is one word in
    # `bitwise_binary` and these cases become "match".
    #
    # `c_error` and not "both_error": torch computes here, and recording it
    # as a mutual refusal would misdescribe which side is missing something.
    for a_dtype, b_dtype, upstream in [
        ("int64", "bool", "int64"),
        ("uint8", "int16", "int16"),
    ]:
        a_t, a_c = pair_from_flat(
            torch_module, c_module, _promote_flat(a_dtype, "a"), (2, 2), a_dtype
        )
        b_t, b_c = pair_from_flat(
            torch_module, c_module, _promote_flat(b_dtype, "b"), (2, 2), b_dtype
        )
        cases.append(
            Case(
                name=f"bitwise_or.Tensor(promote {a_dtype} x {b_dtype} -- torch gives "
                     f"{upstream}, the shim refuses)",
                op=op,
                run_torch=lambda a_t=a_t, b_t=b_t: torch_call(a_t, b_t),
                run_c=lambda a_c=a_c, b_c=b_c: c_module._aten_dispatch(op, a_c, b_c),
                expect="c_error",
                note="same table as bitwise_and, wired only for bitwise_and because only "
                     "bitwise_and has a measured caller",
            )
        )
    return cases


def bitwise_or_scalar_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.bitwise_or.Scalar"
    cases: list[Case] = []
    for dtype_name in _BITWISE_INT_DTYPES:
        cases.append(
            _binary_scalar_case(
                torch_module, c_module, op, torch_call, dtype_name,
                [0b1100, 0b1010, 0b0000, 0], (2, 2), 0b0001, "x | 0b0001",
            )
        )
    return cases


# --- aten.bitwise_not.default -----------------------------------------------
# `__invert__`. See the bool-construction note above bitwise_and_tensor_cases.

_BITWISE_NOT_SIGNED = [0, -1, 5, -5]
_BITWISE_NOT_UNSIGNED = [0, 1, 5, 250]


def bitwise_not_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.bitwise_not.default"
    cases: list[Case] = []
    for dtype_name in ["int64", "int32", "int16"]:
        cases.append(_unary_case(torch_module, c_module, op, torch_call, dtype_name, _BITWISE_NOT_SIGNED, (2, 2), "bitwise not, signed"))
    cases.append(_unary_case(torch_module, c_module, op, torch_call, "uint8", _BITWISE_NOT_UNSIGNED, (2, 2), "bitwise not, unsigned"))
    return cases


# --- aten.eq.{Tensor,Scalar} / aten.lt.{Tensor,Scalar} / aten.ne.{Tensor,Scalar} --
# `__eq__`, `__lt__`, `ne` -- probe confirmed Scalar-overload comparisons
# keep the Python scalar as a Scalar (same family as bitwise_and/or above).

_CMP_DTYPES = ["float64", "float32", "float16", "bfloat16", "int64", "int32", "int16", "uint8"]
_CMP_SCENARIOS: list[dict] = [
    dict(a_flat=[1, 2, 3, 4], a_shape=(2, 2), b_flat=[1, 5, 3, 0], b_shape=(2, 2), note="mixed equal/unequal"),
    dict(a_flat=[7], a_shape=(), b_flat=[1, 7, 3, 4], b_shape=(2, 2), note="scalar (0-d) broadcast"),
]


def eq_tensor_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.eq.Tensor"
    cases: list[Case] = []
    for dtype_name in _CMP_DTYPES:
        for sc in _CMP_SCENARIOS:
            cases.append(
                _binary_tensor_case(
                    torch_module, c_module, op, torch_call, dtype_name,
                    sc["a_flat"], sc["a_shape"], sc["b_flat"], sc["b_shape"], sc["note"],
                )
            )
    return cases


def eq_scalar_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.eq.Scalar"
    cases: list[Case] = []
    for dtype_name in _CMP_DTYPES:
        cases.append(
            _binary_scalar_case(
                torch_module, c_module, op, torch_call, dtype_name,
                [1, 2, 3, 4], (2, 2), 3, "x == 3, as reached from __eq__ with a python scalar",
            )
        )
    return cases


def lt_tensor_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.lt.Tensor"
    cases: list[Case] = []
    for dtype_name in _CMP_DTYPES:
        for sc in _CMP_SCENARIOS:
            cases.append(
                _binary_tensor_case(
                    torch_module, c_module, op, torch_call, dtype_name,
                    sc["a_flat"], sc["a_shape"], sc["b_flat"], sc["b_shape"], sc["note"],
                )
            )
    return cases


def lt_scalar_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.lt.Scalar"
    cases: list[Case] = []
    for dtype_name in _CMP_DTYPES:
        cases.append(
            _binary_scalar_case(
                torch_module, c_module, op, torch_call, dtype_name,
                [1, 2, 3, 4], (2, 2), 3, "x < 3, as reached from __lt__ with a python scalar",
            )
        )
    return cases


def ne_tensor_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.ne.Tensor"
    cases: list[Case] = []
    for dtype_name in _CMP_DTYPES:
        for sc in _CMP_SCENARIOS:
            cases.append(
                _binary_tensor_case(
                    torch_module, c_module, op, torch_call, dtype_name,
                    sc["a_flat"], sc["a_shape"], sc["b_flat"], sc["b_shape"], sc["note"],
                )
            )
    return cases


def ne_scalar_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.ne.Scalar"
    cases: list[Case] = []
    for dtype_name in _CMP_DTYPES:
        cases.append(
            _binary_scalar_case(
                torch_module, c_module, op, torch_call, dtype_name,
                [1, 2, 3, 4], (2, 2), 3, "x.ne(3) -- attention-mask padding check style",
            )
        )
    return cases


# --- aten._local_scalar_dense.default ---------------------------------------
# `__bool__` -- probe: `bool(tensor)` dispatches straight to
# `_local_scalar_dense` for an already-0-d tensor (no `lift_fresh` involved
# once the tensor exists). Returns a plain Python scalar, not a Tensor, so
# this reuses `_scalar_match_check` like `is_floating_point_cases` above.

_LOCAL_SCALAR_DENSE_DTYPES = ["float64", "float32", "float16", "bfloat16", "int64", "int32", "int16", "uint8"]


def local_scalar_dense_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten._local_scalar_dense.default"
    cases: list[Case] = []
    for dtype_name in _LOCAL_SCALAR_DENSE_DTYPES:
        for value, note in [(0, "falsy scalar -- backs bool(x)"), (1, "truthy scalar -- backs bool(x)")]:
            a_t, a_c = pair_from_flat(torch_module, c_module, [value], (), dtype_name)
            cases.append(
                Case(
                    name=f"_local_scalar_dense(dtype={dtype_name}, value={value})",
                    op=op,
                    run_torch=lambda a_t=a_t: torch_call(a_t),
                    run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c),
                    value_check=_scalar_match_check,
                    note=note + " -- returns a plain Python scalar, not a Tensor; backs __bool__ extraction",
                )
            )
    return cases


# --- aten.select.int / aten.slice.Tensor / aten.index.Tensor ---------------
# `__getitem__` -- probe found three distinct overloads depending on the
# index expression's shape: an int index -> select.int, a slice -> slice.
# Tensor, a tensor/bool-mask index -> index.Tensor (via a Tensor?[] list of
# indices). All three are given builders since real code hits all three
# forms.

_SELECT_DTYPES = ["float64", "float32", "int64", "int32", "uint8"]


def select_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.select.int"
    cases: list[Case] = []
    for dtype_name in _SELECT_DTYPES:
        a_t, a_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4, 5, 6], (2, 3), dtype_name)
        cases.append(
            Case(
                name=f"select(dtype={dtype_name}, dim=0, index=1)",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, 0, 1),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, 0, 1),
                note="x[1] -- first-axis row selection",
            )
        )
        cases.append(
            Case(
                name=f"select(dtype={dtype_name}, dim=-1, index=-1)",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, -1, -1),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, -1, -1),
                note="negative dim and index",
            )
        )
    return cases


def slice_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.slice.Tensor"
    cases: list[Case] = []
    for dtype_name in _SELECT_DTYPES:
        a_t, a_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4, 5, 6, 7, 8], (2, 4), dtype_name)
        cases.append(
            Case(
                name=f"slice(dtype={dtype_name}, dim=1, start=1, end=3, step=1)",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, 1, 1, 3, 1),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, 1, 1, 3, 1),
                note="x[:, 1:3] -- last-axis slicing",
            )
        )
        cases.append(
            Case(
                name=f"slice(dtype={dtype_name}, dim=1, start=None, end=None, step=1) [identity]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, 1, None, None, 1),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, 1, None, None, 1),
                note="x[:, :] -- identity slice",
            )
        )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # self/dim/start/end/step all by keyword.
    kw_t, kw_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4, 5, 6, 7, 8], (2, 4), "float32")
    cases.append(
        Case(
            name="slice(self=/dim=/start=/end=/step= all by keyword)",
            op=op,
            run_torch=lambda: torch_call(self=kw_t, dim=1, start=1, end=3, step=1),
            run_c=lambda: c_module._aten_dispatch(op, self=kw_c, dim=1, start=1, end=3, step=1),
        )
    )

    # **The one aliasing relationship in this shim that still disagrees with
    # upstream**, recorded as a divergence so it prints every run and so the
    # case *fails if it silently heals*.
    #
    # `slice.Tensor` at step 1 narrows and shares storage; above step 1 it
    # reaches the result through `index_select`, which copies. So a write
    # through `x[::2]` is seen by `x` upstream and lost here. It cannot be
    # closed inside candle's public API: a stepped view needs a `Layout` with a
    # stride of `step` over the *input's* storage, and the only public pairing
    # of a storage with a layout is `Tensor::from_storage`, documented as
    # contiguous-only and taking a `Storage` that `Tensor::storage()`
    # (`pub(crate)`) will not hand over. docs/VIEWS.md §6.4.
    #
    # `__setitem__` refuses a step above 1 by name for exactly this reason, so
    # the door a caller writes through does not reach it; this case reaches it
    # deliberately, through the dispatch key.
    def _step_two_write(is_torch, base):
        if is_torch:
            view = torch_module.ops.aten.slice.Tensor(base, 0, 0, 4, 2)
            torch_module.ops.aten.fill_.Scalar(view, 0.0)
        else:
            view = c_module._aten_dispatch(op, base, 0, 0, 4, 2)
            c_module._aten_dispatch("aten.fill_.Scalar", view, 0.0)
        return base

    cases.append(
        Case(
            name="base after fill_(x[0:4:2], 0.0) [reads the BASE] -- step > 1 is a copy here",
            op=op,
            run_torch=lambda: _step_two_write(
                True, torch_module.tensor([1.0, 2.0, 3.0, 4.0])),
            run_c=lambda: _step_two_write(
                False, c_module._tensor_from_flat([1.0, 2.0, 3.0, 4.0], [4],
                                                 dtype=c_module.float32)),
            expect="diverge",
            note="a step-2 slice aliases upstream and is materialised here, so the write "
                 "reaches the base upstream ([0,2,0,4]) and is lost here ([1,2,3,4]). "
                 "candle has no public constructor for a stepped view -- docs/VIEWS.md §6.4",
        )
    )
    return cases


def index_tensor_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.index.Tensor"
    cases: list[Case] = []
    for dtype_name in ["float64", "float32", "int64", "int32"]:
        a_t, a_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4, 5, 6], (2, 3), dtype_name)
        idx_t, idx_c = pair_from_flat(torch_module, c_module, [0, 1], (2,), "int64")
        cases.append(
            Case(
                name=f"index(dtype={dtype_name}, integer index tensor)",
                op=op,
                run_torch=lambda a_t=a_t, idx_t=idx_t: torch_call(a_t, [idx_t]),
                run_c=lambda a_c=a_c, idx_c=idx_c: c_module._aten_dispatch(op, a_c, [idx_c]),
                note="x[idx_tensor] -- advanced (fancy) indexing",
            )
        )
        # Boolean-mask indexing needs an actual bool tensor. `_C`'s
        # `_tensor_from_flat` refuses to build one directly (BOOL.md §6.3,
        # see the note above bitwise_and_tensor_cases) and no other
        # bool-producing op is implemented yet either, so construction is
        # deferred into each lambda -- run_c's failure is then caught by
        # compare.py's normal per-case try/except instead of crashing the
        # whole harness run at case-list-build time.
        a_flat, a_shape = [1, 2, 3, 4, 5, 6], (2, 3)
        mask_flat = [True, False, True, False, True, False]
        cases.append(
            Case(
                name=f"index(dtype={dtype_name}, boolean mask)",
                op=op,
                run_torch=lambda dtype_name=dtype_name, a_flat=a_flat, a_shape=a_shape, mask_flat=mask_flat: torch_call(
                    torch_module.tensor(a_flat, dtype=dt.torch_dtype(torch_module, dtype_name)).reshape(list(a_shape)),
                    [torch_module.tensor(mask_flat).reshape(list(a_shape))],
                ),
                run_c=lambda dtype_name=dtype_name, a_flat=a_flat, a_shape=a_shape, mask_flat=mask_flat: c_module._aten_dispatch(
                    op,
                    c_module._tensor_from_flat(a_flat, list(a_shape), dtype=dt.c_dtype(c_module, dtype_name)),
                    [c_module._tensor_from_flat([int(v) for v in mask_flat], list(a_shape), dtype=c_module.bool)],
                ),
                note="x[bool_mask] -- boolean mask indexing, as in attention masking",
            )
        )
    cases.extend(_multi_index_cases(torch_module, c_module, torch_call))
    return cases


# The rank-4 corpus for multi-tensor advanced indexing.
#
# Shape agreement is the weak half of this check; the value comparison is the
# strong half. The failure this op invites is a result of exactly the right
# shape with the axes in the wrong order: on a `(2,3,4,5)` tensor both
# `x[i,:,j]` and `x[:,i,j]` give a rank-4 result, and a kernel that always
# splices the broadcast block in place -- or always moves it to the front --
# gets one of them right and silently transposes the other. `compare.py`'s
# default pipeline compares every element, so these catch it; the cases where
# that is the whole point say ORDER-SENSITIVE in their note.
#
# Everything here was measured against torch 2.13.0: shapes, values, and the
# exact text of all four refusals.
_MULTI_INDEX_SHAPE = (2, 3, 4, 5)


def _multi_index_specs():
    """(name, spec, note). A spec names index tensors as
    `(flat, shape, dtype)` and un-indexed axes as `None`, so each backend
    builds its own tensors instead of sharing one."""
    i2 = ([0, 1], (2, 1), "int64")
    j3 = ([0, 1, 2], (3,), "int64")
    i2f = ([0, 1], (2,), "int64")
    j2 = ([0, 2], (2,), "int64")
    k2 = ([1, 3], (2,), "int64")
    return [
        ("adjacent-leading", [i2, j3], "broadcast (2,3) splices at axis 0"),
        ("adjacent-middle", [None, i2, j3],
         "ORDER-SENSITIVE: broadcast splices at axis 1, not at the front"),
        ("adjacent-trailing", [None, None, i2f, j2],
         "ORDER-SENSITIVE: broadcast splices at axis 2"),
        ("separated-by-one", [i2, None, j3],
         "ORDER-SENSITIVE: separated, so the broadcast moves to the FRONT"),
        ("separated-by-two", [i2, None, None, j3],
         "ORDER-SENSITIVE: separated by two axes, broadcast moves to the front"),
        ("separated-outer", [None, i2, None, j3],
         "ORDER-SENSITIVE: axes 1 and 3 indexed, broadcast moves to the front"),
        ("three-adjacent", [i2f, j2, k2], "three index tensors, all adjacent"),
        ("three-separated", [i2f, None, j2, k2],
         "ORDER-SENSITIVE: three index tensors, the first separated from the rest"),
        ("negative-indices", [([-1, 0], (2,), "int64"), ([0, 1], (2,), "int64")],
         "negative indices wrap, as in Python"),
        ("zero-dim-pair", [([1], (), "int64"), ([2], (), "int64")],
         "0-d index tensors contribute no result axes"),
        ("zero-dim-mixed", [([1], (), "int64"), j2], "0-d broadcast against 1-d"),
        ("empty-pair", [([], (0,), "int64"), ([], (0,), "int64")],
         "empty index tensors give a zero-length result axis"),
        ("int32-index", [([0, 1], (2,), "int32"), j2],
         "int32 is accepted alongside int64"),
        ("single-index-unchanged", [i2f],
         "the pre-existing single-index path must keep working"),
    ]


def _build_index_list(module, spec, is_c):
    out = []
    for entry in spec:
        if entry is None:
            out.append(None)
            continue
        flat, shape, dtype_name = entry
        if is_c:
            out.append(module._tensor_from_flat(list(flat), list(shape),
                                                dtype=dt.c_dtype(module, dtype_name)))
        else:
            out.append(module.tensor(
                list(flat), dtype=dt.torch_dtype(module, dtype_name)).reshape(list(shape)))
    return out


def _multi_index_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.index.Tensor"
    cases: list[Case] = []
    n = 1
    for d in _MULTI_INDEX_SHAPE:
        n *= d
    flat = list(range(n))

    for name, spec, note in _multi_index_specs():
        a_t, a_c = pair_from_flat(torch_module, c_module, flat, _MULTI_INDEX_SHAPE, "float32")
        cases.append(
            Case(
                name=f"index(rank-4, {name})",
                op=op,
                run_torch=lambda a_t=a_t, spec=spec: torch_call(
                    a_t, _build_index_list(torch_module, spec, False)),
                run_c=lambda a_c=a_c, spec=spec: c_module._aten_dispatch(
                    op, a_c, _build_index_list(c_module, spec, True)),
                note=note,
            )
        )

    # Boolean masks, one of them mixed with an integer index. Built inside the
    # lambdas for the same reason the single-mask case above is: `_C` cannot
    # construct a bool tensor at case-list-build time without the failure
    # taking down the whole harness run.
    mask_specs = [
        ("mask-1d", [True, False], (2,), None, "a rank-1 mask covers one axis"),
        ("mask-2d", [True, False, True, False, True, False], (2, 3), None,
         "a rank-2 mask covers two axes and yields one result axis"),
        ("mask-plus-int", [True, False], (2,), ([0, 1, 2], (3,)),
         "a mask's nonzero count broadcasts against an integer index"),
    ]
    # `uint8` is upstream's deprecated spelling of `bool`, NOT an integer
    # index: `x[uint8([0, 1])]` gathers the *true* positions (one of them),
    # giving a leading axis of 1, where reading it as an integer index would
    # give a leading axis of 2 and different rows entirely. Measured on torch
    # 2.13.0, which emits a deprecation warning confirming the mask reading.
    cases.append(
        Case(
            name="index(rank-4, uint8-is-a-mask-not-an-index)",
            op=op,
            run_torch=lambda: torch_call(
                torch_module.tensor(flat, dtype=dt.torch_dtype(torch_module, "float32")).reshape(
                    list(_MULTI_INDEX_SHAPE)),
                [torch_module.tensor([0, 1], dtype=torch_module.uint8)],
            ),
            run_c=lambda: c_module._aten_dispatch(
                op,
                c_module._tensor_from_flat(flat, list(_MULTI_INDEX_SHAPE),
                                           dtype=dt.c_dtype(c_module, "float32")),
                [c_module._tensor_from_flat([0, 1], [2], dtype=c_module.uint8)],
            ),
            note="uint8 indexes as a boolean mask (deprecated spelling), not by value",
        )
    )
    for name, mask_flat, mask_shape, extra, note in mask_specs:
        def run(module, is_c, mask_flat=mask_flat, mask_shape=mask_shape, extra=extra):
            if is_c:
                base = module._tensor_from_flat(flat, list(_MULTI_INDEX_SHAPE),
                                                dtype=dt.c_dtype(module, "float32"))
                idx = [module._tensor_from_flat([int(v) for v in mask_flat],
                                                list(mask_shape), dtype=module.bool)]
                if extra is not None:
                    idx.append(module._tensor_from_flat(list(extra[0]), list(extra[1]),
                                                        dtype=module.int64))
                return module._aten_dispatch(op, base, idx)
            base = module.tensor(flat, dtype=dt.torch_dtype(module, "float32")).reshape(
                list(_MULTI_INDEX_SHAPE))
            idx = [module.tensor(mask_flat).reshape(list(mask_shape))]
            if extra is not None:
                idx.append(module.tensor(list(extra[0])).reshape(list(extra[1])))
            return torch_call(base, idx)
        cases.append(
            Case(
                name=f"index(rank-4, {name})",
                op=op,
                run_torch=lambda run=run: run(torch_module, False),
                run_c=lambda run=run: run(c_module, True),
                note=note,
            )
        )

    # The four refusals, each measured on upstream first. `both_error` rather
    # than `c_error`: upstream raises here too, and the point is that the shim
    # does not compute where upstream declines to.
    refusals = [
        ("incompatible-broadcast",
         [([0, 1], (2,), "int64"), ([0, 1, 2], (3,), "int64")],
         "IndexError: shape mismatch -- (2,) and (3,) do not broadcast"),
        ("out-of-range",
         [([0, 1], (2,), "int64"), ([0, 7], (2,), "int64")],
         "IndexError: 7 is out of bounds for dimension 1, which has size 3"),
        ("negative-out-of-range",
         [([-3], (1,), "int64"), ([0], (1,), "int64")],
         "IndexError: -3 is out of bounds for dimension 0, which has size 2"),
        ("too-many-indices",
         [([0], (1,), "int64")] * 5,
         "IndexError: too many indices for a rank-4 tensor"),
    ]
    for name, spec, note in refusals:
        a_t, a_c = pair_from_flat(torch_module, c_module, flat, _MULTI_INDEX_SHAPE, "float32")
        cases.append(
            Case(
                name=f"index(rank-4, {name})",
                op=op,
                run_torch=lambda a_t=a_t, spec=spec: torch_call(
                    a_t, _build_index_list(torch_module, spec, False)),
                run_c=lambda a_c=a_c, spec=spec: c_module._aten_dispatch(
                    op, a_c, _build_index_list(c_module, spec, True)),
                expect="both_error",
                note=note,
            )
        )
    return cases


# --- aten.any.default / aten.any.dim ----------------------------------------
# `any` -- probed on int input (`torch.any` treats any nonzero element as
# true regardless of dtype), avoiding the bool-construction constraint
# noted above bitwise_and_tensor_cases entirely rather than working around
# it, since int input exercises the real op just as well.

def any_default_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.any.default"
    cases: list[Case] = []
    for flat, shape, note in [
        ([1, 0, 1, 0], (2, 2), "some true"),
        ([0, 0, 0, 0], (2, 2), "all false"),
        ([1, 1, 1, 1], (2, 2), "all true"),
    ]:
        cases.append(_unary_case(torch_module, c_module, op, torch_call, "int64", flat, shape, note))
    cases.extend(_bool_reduce_dtype_cases(torch_module, c_module, torch_call, op))
    cases.extend(_bool_reduce_empty_cases(torch_module, c_module, torch_call, op))
    return cases


def any_dim_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.any.dim"
    cases: list[Case] = []
    scenarios = [
        dict(flat=[1, 0, 0, 0, 1, 1], shape=(2, 3), dim=1, keepdim=False, note="along last dim"),
        dict(flat=[1, 0, 0, 0, 1, 1], shape=(2, 3), dim=1, keepdim=True, note="along last dim, keepdim"),
        dict(flat=[1, 0, 0, 0, 1, 1], shape=(2, 3), dim=0, keepdim=False, note="along first dim"),
    ]
    for sc in scenarios:
        a_t, a_c = pair_from_flat(torch_module, c_module, sc["flat"], sc["shape"], "int64")
        dim, keepdim = sc["dim"], sc["keepdim"]
        cases.append(
            Case(
                name=f"any(dtype=int64, dim={dim}, keepdim={keepdim}) [{sc['note']}]",
                op=op,
                run_torch=lambda a_t=a_t, dim=dim, keepdim=keepdim: torch_call(a_t, dim, keepdim),
                run_c=lambda a_c=a_c, dim=dim, keepdim=keepdim: c_module._aten_dispatch(op, a_c, dim, keepdim),
                note=sc["note"],
            )
        )
    cases.extend(_bool_reduce_dim_cases(torch_module, c_module, torch_call, op))
    return cases


# --- aten.all.{default,dim,dims}, and the two rules `any` had wrong ----------
#
# `all` is `any` with the reduction turned around, and writing it from `any`'s
# shape would have copied two defects into a second op, because `any`'s cases
# probe only `int64` on non-empty input:
#
#   * **dtype.** The result is `torch.bool` for every dtype EXCEPT `uint8`,
#     where it is `uint8` -- upstream's own `torch.all` docstring says so, and
#     it is measured on both ops and all three forms. `any` returned
#     `torch.bool` unconditionally and no case could see it.
#   * **empty.** `torch.tensor([]).any()` is `False`; `torch.tensor([]).all()`
#     is `True`. `any`'s early return hardcoded a zero, which is right for
#     `any` and would have been wrong for `all` had it been shared verbatim.
#     Over a *dimension* candle refused outright ("empty tensor for reduce"),
#     and the answer there is the identity broadcast over the surviving axes:
#     `torch.zeros(0,3).all(0)` is `[True,True,True]` -- three trues out of
#     nothing -- while `torch.zeros(0,3).all(1)` is the empty `[]`.
#
# The shared builders below are applied to BOTH ops, which is the point: a
# rule stated once and fed to both is what stops the pair drifting again.

# `int8` is deliberately absent: candle cannot store it, so
# `_tensor_from_flat` refuses and the pair cannot even be built. `uint8` --
# the one dtype the rule turns on -- is storable, which is what matters here.
_BOOL_REDUCE_DTYPES = ["uint8", "int32", "int64", "bool", "float32", "float16"]


def _bool_reduce_dtype_cases(torch_module, c_module, torch_call, op) -> list[Case]:
    """The dtype ladder, on the whole-tensor form of `any`/`all`.

    `uint8` is the row that separates "the result is always bool" from
    upstream's actual rule, and it is the only one. The other six are here so
    that a kernel which got `uint8` right by returning the *input* dtype fails
    too."""
    name = op.split(".")[1]
    cases: list[Case] = []
    for dtype_name in _BOOL_REDUCE_DTYPES:
        for flat, note in (
            ([1, 1, 1, 1], "all nonzero"),
            ([1, 0, 1, 0], "mixed"),
            ([0, 0, 0, 0], "all zero"),
        ):
            a_t, a_c = pair_from_flat(torch_module, c_module, flat, (2, 2), dtype_name)
            cases.append(
                Case(
                    name=f"{name}(dtype={dtype_name}, {note}) [result dtype]",
                    op=op,
                    run_torch=lambda a_t=a_t: torch_call(a_t),
                    run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c),
                    note="bool out for every dtype except uint8, which stays uint8",
                )
            )
    # NaN is non-zero and therefore true. A kernel that compared against zero
    # after a cast that turned NaN into 0 would answer the other way, and only
    # here.
    n_t, n_c = pair_from_flat(
        torch_module, c_module, [float("nan"), 1.0], (2,), "float32")
    cases.append(
        Case(
            name=f"{name}(float32, [nan, 1.]) [NaN counts as nonzero]",
            op=op,
            run_torch=lambda: torch_call(n_t),
            run_c=lambda: c_module._aten_dispatch(op, n_c),
            note="measured: all() is True and any() is True -- nan != 0",
        )
    )
    # A tensor whose only nonzero is a NEGATIVE number: "nonzero", not
    # "positive". `[-1, -2]` is all-true; a kernel written as `x > 0` says
    # all-false.
    g_t, g_c = pair_from_flat(torch_module, c_module, [-1, -2, -3, -4], (2, 2), "int64")
    cases.append(
        Case(
            name=f"{name}(int64, all negative) [nonzero, not positive]",
            op=op,
            run_torch=lambda: torch_call(g_t),
            run_c=lambda: c_module._aten_dispatch(op, g_c),
            note="measured: [-1,-2,-3,-4].all() is True; `x > 0` would say False",
        )
    )
    # 0-d input: there is no axis to reduce and the answer is the element's own
    # truthiness.
    for flat, note in (([5], "nonzero scalar"), ([0], "zero scalar")):
        s_t, s_c = pair_from_flat(torch_module, c_module, flat, (), "int64")
        cases.append(
            Case(
                name=f"{name}(int64 0-d, {note})",
                op=op,
                run_torch=lambda s_t=s_t: torch_call(s_t),
                run_c=lambda s_c=s_c: c_module._aten_dispatch(op, s_c),
                note="rank 0: nothing to reduce over",
            )
        )
    return cases


def _bool_reduce_empty_cases(torch_module, c_module, torch_call, op) -> list[Case]:
    """The empty whole-tensor reduction -- where `any` and `all` disagree.

    `any` over nothing is False and `all` over nothing is True, so a shared
    early return that hardcodes either one is wrong for exactly one of the two
    ops on exactly this input."""
    name = op.split(".")[1]
    cases: list[Case] = []
    for dtype_name in ["float32", "int64", "uint8"]:
        for shape, note in (((0,), "1-d empty"), ((0, 3), "2-d, first axis empty")):
            e_t, e_c = pair_from_flat(torch_module, c_module, [], shape, dtype_name)
            cases.append(
                Case(
                    name=f"{name}(dtype={dtype_name}, {note}) [the identity]",
                    op=op,
                    run_torch=lambda e_t=e_t: torch_call(e_t),
                    run_c=lambda e_c=e_c: c_module._aten_dispatch(op, e_c),
                    note="any over nothing is False; all over nothing is True",
                )
            )
    return cases


def _bool_reduce_dim_cases(torch_module, c_module, torch_call, op) -> list[Case]:
    """The `.dim` form: dtype, negative dims, keepdim, and the empty axis."""
    name = op.split(".")[1]
    cases: list[Case] = []
    flat = [1, 0, 1, 1, 1, 1]
    for dtype_name in ["uint8", "int64", "bool", "float32"]:
        for dim, keepdim in ((0, False), (1, False), (1, True), (-1, False)):
            a_t, a_c = pair_from_flat(torch_module, c_module, flat, (2, 3), dtype_name)
            cases.append(
                Case(
                    name=f"{name}(dtype={dtype_name}, dim={dim}, keepdim={keepdim})",
                    op=op,
                    run_torch=lambda a_t=a_t, dim=dim, keepdim=keepdim: torch_call(
                        a_t, dim, keepdim),
                    run_c=lambda a_c=a_c, dim=dim, keepdim=keepdim: c_module._aten_dispatch(
                        op, a_c, dim, keepdim),
                    note="uint8 keeps uint8 here too; -1 must mean the last axis",
                )
            )
    # Reducing over a zero-length axis: the identity, once per surviving
    # element. Reducing over the axis that is NOT zero-length: an empty result.
    # One shape, two dims, and they answer differently -- which is why the
    # kernel computes the reduced shape rather than short-circuiting on
    # "the input is empty".
    for dim, note in ((0, "over the empty axis -> identity x 3"),
                      (1, "over the full axis -> empty result")):
        for keepdim in (False, True):
            e_t, e_c = pair_from_flat(torch_module, c_module, [], (0, 3), "int64")
            cases.append(
                Case(
                    name=f"{name}((0,3), dim={dim}, keepdim={keepdim}) [{note}]",
                    op=op,
                    run_torch=lambda e_t=e_t, dim=dim, keepdim=keepdim: torch_call(
                        e_t, dim, keepdim),
                    run_c=lambda e_c=e_c, dim=dim, keepdim=keepdim: c_module._aten_dispatch(
                        op, e_c, dim, keepdim),
                    note=note,
                )
            )
    return cases


def all_default_cases(torch_module, c_module, torch_call) -> list[Case]:
    """`aten.all(Tensor self)` -- sam3_video's wall.

    `masking_utils.py:330` asks `padding_mask.all()` before it will skip
    building a bidirectional mask, on a `bool` tensor.

    The plausible wrong implementations, and what separates each:

      * **`any` with the comparison flipped and nothing else** -- passes every
        non-empty case and answers `False` where upstream answers `True` on
        an empty tensor. `_bool_reduce_empty_cases`.
      * **"the result is always bool"** -- passes six of the seven dtypes.
        `uint8` is the row. `_bool_reduce_dtype_cases`.
      * **"all elements are positive"** -- passes every case built from 0/1
        data, which is what a mask is. The all-negative case is the one.
      * **"NaN is not true"** -- upstream counts NaN as nonzero.
    """
    op = "aten.all.default"
    cases: list[Case] = []
    for flat, shape, note in [
        ([1, 0, 1, 0], (2, 2), "some true"),
        ([0, 0, 0, 0], (2, 2), "all false"),
        ([1, 1, 1, 1], (2, 2), "all true"),
    ]:
        cases.append(
            _unary_case(torch_module, c_module, op, torch_call, "int64", flat, shape, note))
    cases.extend(_bool_reduce_dtype_cases(torch_module, c_module, torch_call, op))
    cases.extend(_bool_reduce_empty_cases(torch_module, c_module, torch_call, op))
    cases.extend(_all_member_cases(torch_module, c_module))
    return cases


def all_dim_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.all.dim"
    cases = _bool_reduce_dim_cases(torch_module, c_module, torch_call, op)
    # The member with an *int* dim, which binds `all.dim` rather than
    # `all.dims` -- the two are distinguished only by the argument's Python
    # type, and getting the table order wrong sends both to one kernel.
    pair = pair_from_flat(torch_module, c_module, [1, 0, 1, 1, 1, 1], (2, 3), "bool")
    cases.append(
        _member_case(
            torch_module, c_module, op,
            "member x.all(1) (dtype=bool)", "bool", [pair],
            lambda m, a: a.all(1),
            note="an int dim binds all.dim, not all.dims",
        )
    )
    return cases


def all_dims_cases(torch_module, c_module, torch_call) -> list[Case]:
    """`aten.all.dims` -- the `int[]?` form, whose `dim=None` means *every*
    axis rather than "missing"."""
    op = "aten.all.dims"
    cases: list[Case] = []
    flat = [1, 0, 1, 1, 1, 1]
    for dtype_name in ["uint8", "int64", "bool"]:
        for dims, keepdim in ((None, False), ((0,), False), ((0, 1), False),
                              ((1,), True), ((0, 1), True)):
            a_t, a_c = pair_from_flat(torch_module, c_module, flat, (2, 3), dtype_name)
            cases.append(
                Case(
                    name=f"all.dims(dtype={dtype_name}, dim={dims}, keepdim={keepdim})",
                    op=op,
                    run_torch=lambda a_t=a_t, dims=dims, keepdim=keepdim: torch_call(
                        a_t, dims, keepdim),
                    run_c=lambda a_c=a_c, dims=dims, keepdim=keepdim: c_module._aten_dispatch(
                        op, a_c, dims, keepdim),
                    note="dim=None on this overload is every axis, not a missing argument",
                )
            )
    pair = pair_from_flat(torch_module, c_module, [1, 0, 1, 1, 1, 1], (2, 3), "bool")
    cases.append(
        _member_case(
            torch_module, c_module, op,
            "member x.all(dim=(0, 1)) (dtype=bool)", "bool", [pair],
            lambda m, a: a.all(dim=(0, 1)),
            note="a tuple dim binds all.dims",
        )
    )
    return cases


def _all_member_cases(torch_module, c_module) -> list[Case]:
    """`x.all()` and `torch.all(x)` -- the two spellings.

    `sam3_video` uses the member. Golden compares by dispatch key and is
    structurally blind to both, so deleting either table entry fails here and
    nothing else."""
    op = "aten.all.default"
    cases: list[Case] = []
    for dtype_name in ["bool", "int64", "uint8"]:
        for flat, note in (([1, 1, 1, 1], "all true"), ([1, 0, 1, 1], "one false")):
            pair = pair_from_flat(torch_module, c_module, flat, (2, 2), dtype_name)
            cases.append(
                _member_case(
                    torch_module, c_module, op,
                    f"member x.all() (dtype={dtype_name}, {note})", dtype_name, [pair],
                    lambda m, a: a.all(),
                    note="masking_utils.py:330 padding_mask.all()",
                )
            )
            pair = pair_from_flat(torch_module, c_module, flat, (2, 2), dtype_name)
            cases.append(
                _member_case(
                    torch_module, c_module, op,
                    f"free torch.all(x) (dtype={dtype_name}, {note})", dtype_name, [pair],
                    lambda m, a: _free(m, "all")(a),
                    note="the free-function spelling; overloads.json entry",
                )
            )
    return cases


# --- aten.clone.default / aten.detach.default -------------------------------
# `clone` (also backs `contiguous()` on a non-contiguous input, see the
# module note above) and `detach` (identity view, drops autograd tracking).


def clone_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.clone.default"
    cases: list[Case] = []
    for dtype_name in ["float64", "float32", "float16", "bfloat16", "int64", "int32", "uint8"]:
        for flat, shape in [([0], ()), ([1, 2, 3], (3,)), ([1, 2, 3, 4], (2, 2))]:
            cases.append(
                _unary_case(
                    torch_module, c_module, op, torch_call, dtype_name, flat, shape,
                    "identity copy -- also backs contiguous() on a non-contiguous input",
                )
            )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # self/memory_format both by keyword. `memory_format` is keyword-only
    # and, unlike every other name here, is never accepted as a value the
    # kernel *reads* -- it is only ever rejected by name (contiguous_format/
    # preserve_format are silently accepted no-ops, anything else raises).
    # So a value the shim accepts cannot tell a working lookup from a
    # tampered one that treats the argument as absent -- absent and
    # "contiguous_format" behave identically. A value the shim *refuses*
    # can: if the lookup silently misses, the refusal never fires and the
    # case's expect="c_error" flips to "both compute", which fails.
    kw_t, kw_c = pair_from_flat(torch_module, c_module, list(range(24)), (1, 2, 3, 4), "float32")
    cases.append(
        Case(
            name="clone(self=/memory_format= both by keyword) [c_error -- torch computes, shim refuses]",
            op=op,
            run_torch=lambda: torch_call(self=kw_t, memory_format=torch_module.channels_last),
            run_c=lambda: c_module._aten_dispatch(op, self=kw_c, memory_format=torch_module.channels_last),
            expect="c_error",
            note="memory_format=torch.channels_last is not implemented in torch._C shim -- "
                 "see reject_memory_format in rust/torch_c/src/aten.rs",
        )
    )
    return cases


def detach_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.detach.default"
    cases: list[Case] = []
    for dtype_name in ["float64", "float32", "int64", "uint8"]:
        for flat, shape in [([0], ()), ([1, 2, 3, 4], (2, 2))]:
            cases.append(
                _unary_case(torch_module, c_module, op, torch_call, dtype_name, flat, shape, "identity view, drops autograd tracking")
            )
    return cases


# --- aten.cos.default / aten.sin.default / aten.reciprocal.default ---------
# RoPE (cos/sin) and RMSNorm (reciprocal, alongside pow/mean above) inputs.

_TRIG_DTYPES = ["float64", "float32", "float16", "bfloat16"]
_TRIG_SCENARIOS = [
    ([0.0, 1.5707963267948966, 3.141592653589793, -1.5707963267948966], (2, 2), "0/pi-over-2/pi/-pi-over-2 -- RoPE angle boundary values"),
    ([0.1, 0.5, 1.0, 2.0], (2, 2), "assorted angles"),
    ([0.0], (), "0-d"),
]


def cos_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.cos.default"
    cases: list[Case] = []
    for dtype_name in _TRIG_DTYPES:
        for flat, shape, note in _TRIG_SCENARIOS:
            cases.append(_unary_case(torch_module, c_module, op, torch_call, dtype_name, flat, shape, note))
    return cases


def sin_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.sin.default"
    cases: list[Case] = []
    for dtype_name in _TRIG_DTYPES:
        for flat, shape, note in _TRIG_SCENARIOS:
            cases.append(_unary_case(torch_module, c_module, op, torch_call, dtype_name, flat, shape, note))
    return cases


def reciprocal_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.reciprocal.default"
    cases: list[Case] = []
    for dtype_name in _TRIG_DTYPES:
        for flat, shape, note in [
            ([1.0, 2.0, 4.0, 0.5], (2, 2), "assorted magnitudes"),
            ([0.0], (1,), "zero -> +inf"),
            ([-1.0, -4.0], (2,), "negative values"),
            ([2.0], (), "0-d"),
        ]:
            cases.append(_unary_case(torch_module, c_module, op, torch_call, dtype_name, flat, shape, note))
    return cases


# --- aten.cumsum.default -----------------------------------------------------

def cumsum_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.cumsum.default"
    cases: list[Case] = []
    for dtype_name in ["float64", "float32", "float16", "bfloat16", "int64", "int32"]:
        a_t, a_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4, 5, 6], (2, 3), dtype_name)
        cases.append(
            Case(
                name=f"cumsum(dtype={dtype_name}, dim=0)",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, 0),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, 0),
                note="running total along first dim",
            )
        )
        cases.append(
            Case(
                name=f"cumsum(dtype={dtype_name}, dim=-1)",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, -1),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, -1),
                note="running total along last dim, negative dim",
            )
        )
    return cases


# --- aten.expand.default -----------------------------------------------------

def expand_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.expand.default"
    cases: list[Case] = []
    for dtype_name in ["float64", "float32", "int64", "uint8"]:
        a_t, a_c = pair_from_flat(torch_module, c_module, [1, 2], (2, 1), dtype_name)
        cases.append(
            Case(
                name=f"expand(dtype={dtype_name}, (2,1)->(2,3))",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, [2, 3]),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, [2, 3]),
                note="broadcast a singleton dim, as in expanding a KV head across query heads",
            )
        )
        cases.append(
            Case(
                name=f"expand(dtype={dtype_name}, (2,1)->(2,-1)) [keep-dim sentinel]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, [2, -1]),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, [2, -1]),
                note="-1 means 'keep this dim's existing size'",
            )
        )
    a3_t, a3_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4, 5, 6], (2, 3), "float32")
    cases.append(
        Case(
            name="expand(non-singleton dim rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(a3_t, [2, 5]),
            run_c=lambda: c_module._aten_dispatch(op, a3_c, [2, 5]),
            expect="both_error",
            note="expand can only broadcast size-1 dims.",
        )
    )
    return cases


# --- aten.masked_fill.Scalar --------------------------------------------------

def masked_fill_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.masked_fill.Scalar"
    cases: list[Case] = []
    # `mask` must be an actual bool tensor -- torch's own masked_fill_
    # refuses a non-bool mask (probed: "masked_fill_ only supports boolean
    # masks"). `_C`'s `_tensor_from_flat` refuses to build a bool tensor
    # directly (BOOL.md §6.3, see the note above bitwise_and_tensor_cases),
    # and there is no other sanctioned way to get a bool tensor into `_C`
    # either, so -- unlike the ops above that could just drop bool coverage
    # -- masked_fill genuinely cannot be exercised yet. Mask construction is
    # deferred into the run_torch/run_c lambdas (built fresh each call,
    # rather than shared like every other case here) so that, until BOOL.md's
    # gap is closed, this surfaces as an ordinary per-case failure the
    # moment masked_fill lands in `_aten_implemented()` -- not a hard crash
    # of the whole harness run at case-list-construction time.
    a_flat, a_shape = [1.0, 2.0, 3.0, 4.0, 5.0, 6.0], (2, 3)
    mask_flat = [True, False, True, False, True, False]
    for dtype_name in ["float64", "float32", "float16", "bfloat16"]:
        big = _FLOAT_ADD_MAGNITUDE[dtype_name]
        for value, note in [(0.0, "zero fill"), (-big, "large negative -- attention masking style")]:
            cases.append(
                Case(
                    name=f"masked_fill(dtype={dtype_name}, value={value}) [{note}]",
                    op=op,
                    run_torch=lambda dtype_name=dtype_name, value=value: torch_call(
                        torch_module.tensor(a_flat, dtype=dt.torch_dtype(torch_module, dtype_name)).reshape(list(a_shape)),
                        torch_module.tensor(mask_flat).reshape(list(a_shape)),
                        value,
                    ),
                    run_c=lambda dtype_name=dtype_name, value=value: c_module._aten_dispatch(
                        op,
                        c_module._tensor_from_flat(a_flat, list(a_shape), dtype=dt.c_dtype(c_module, dtype_name)),
                        c_module._tensor_from_flat([int(v) for v in mask_flat], list(a_shape), dtype=c_module.bool),
                        value,
                    ),
                    note=note,
                )
            )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # self/mask/value all by keyword.
    cases.append(
        Case(
            name="masked_fill(self=/mask=/value= all by keyword)",
            op=op,
            run_torch=lambda: torch_call(
                self=torch_module.tensor(a_flat, dtype=torch_module.float32).reshape(list(a_shape)),
                mask=torch_module.tensor(mask_flat).reshape(list(a_shape)),
                value=0.0,
            ),
            run_c=lambda: c_module._aten_dispatch(
                op,
                self=c_module._tensor_from_flat(a_flat, list(a_shape), dtype=c_module.float32),
                mask=c_module._tensor_from_flat([int(v) for v in mask_flat], list(a_shape), dtype=c_module.bool),
                value=0.0,
            ),
        )
    )
    return cases


# --- aten.max.default / aten.max.dim -----------------------------------------
# `max.dim` returns a (values, indices) pair (torch: a `torch.return_types.
# max` namedtuple, 2-tuple-indexable) -- see `_pair_result_check` below.

_REDUCE_DTYPES = ["float64", "float32", "float16", "bfloat16", "int64", "int32"]


def max_default_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.max.default"
    cases: list[Case] = []
    for dtype_name in _REDUCE_DTYPES:
        for flat, shape, note in [
            ([1, 5, 2, 9, 0, 3], (2, 3), "global max, flattened"),
            ([-5, -1, -9, -3], (2, 2), "all-negative values"),
            ([7], (1,), "single element"),
        ]:
            cases.append(_unary_case(torch_module, c_module, op, torch_call, dtype_name, flat, shape, note))
    # The case this builder was missing, and its absence was hiding a wrong
    # answer rather than leaving a gap in coverage: candle's reduction *skips*
    # NaN, so `max([3, nan, 1])` came back `3.0` here where upstream gives
    # `nan` (docs/E2E_REAL.md). Every case above passed throughout. The kernel
    # tests for NaN explicitly now, on `max` and `min` alike, and this pins it;
    # `min_default_cases` carries the mirror.
    #
    # Three positions rather than one -- see `min_default_cases`' note for why
    # `at=0` alone is a case that cannot fail, and docs/TRIL.md §3 for the
    # audit that made this uniform across the family.
    nan = float("nan")
    for at, where in [(0, "first"), (1, "middle"), (3, "last")]:
        flat = [1.0, 5.0, 2.0, 9.0]
        flat[at] = nan
        for dtype_name in ["float64", "float32", "float16", "bfloat16"]:
            cases.append(
                _unary_case(
                    torch_module, c_module, op, torch_call, dtype_name, flat, (4,),
                    f"NaN in the {where} position propagates: max() of a tensor containing "
                    f"NaN is NaN (measured) -- torch's rule is IEEE maximum, not fmax",
                )
            )
    return cases


def _pair_result_check(t_res, c_res) -> tuple[bool, str]:
    """For ops returning a (values, indices) pair, like `max.dim` -- torch
    returns a `torch.return_types.max` namedtuple, indexable like a plain
    2-tuple. `values` is compared like any tensor result (dtype/shape/value
    within tolerance); `indices` must match exactly (integer positions)."""
    try:
        t_values, t_indices = t_res[0], t_res[1]
        c_values, c_indices = c_res[0], c_res[1]
    except (TypeError, IndexError, KeyError) as e:
        return False, f"expected a 2-element (values, indices) result on both sides: {e!r}"

    t_dtype, c_dtype = dt.dtype_name(t_values.dtype), dt.dtype_name(c_values.dtype)
    if t_dtype != c_dtype:
        return False, f"values dtype mismatch: torch={t_dtype} c={c_dtype}"
    t_shape = tuple(int(x) for x in t_values.shape)
    c_shape = tuple(int(x) for x in c_values.shape)
    if t_shape != c_shape:
        return False, f"values shape mismatch: torch={t_shape} c={c_shape}"

    tol = dt.tolerance_for(t_dtype)
    t_flat, c_flat = _flatten_values(t_values.tolist()), _flatten_values(c_values.tolist())
    if len(t_flat) != len(c_flat):
        return False, f"values length differs: torch={len(t_flat)} c={len(c_flat)}"
    for i, (x, y) in enumerate(zip(t_flat, c_flat)):
        xf, yf = float(x), float(y)
        # NaN is a *result* for these ops, not a failure: torch orders NaN as
        # the greatest element, so `sort` and `topk` hand it back and it
        # arrives here. `math.isclose(nan, nan)` is False, so without this the
        # two sides agreeing on NaN reads as a mismatch -- which is exactly
        # what happened the first time a NaN case was added.
        if math.isnan(xf) or math.isnan(yf):
            if math.isnan(xf) and math.isnan(yf):
                continue
            return False, f"values[{i}] mismatch: torch={x!r} c={y!r} (NaN on one side only)"
        if not math.isclose(xf, yf, rel_tol=tol.rtol, abs_tol=tol.atol):
            return False, f"values[{i}] mismatch: torch={x!r} c={y!r}"

    t_idx_shape = tuple(int(x) for x in t_indices.shape)
    c_idx_shape = tuple(int(x) for x in c_indices.shape)
    if t_idx_shape != c_idx_shape:
        return False, f"indices shape mismatch: torch={t_idx_shape} c={c_idx_shape}"
    # The indices' *dtype*, not just their values. Upstream promises `int64`
    # here, and that index goes straight into `index_select`/`gather`/
    # `embedding`; a shim returning value-identical `int32` passes every other
    # check in this function and breaks downstream instead. `--self-test`
    # reported this as `_pair_result_check + dtype-last` (docs/HARNESS.md §6).
    t_idx_dtype, c_idx_dtype = dt.dtype_name(t_indices.dtype), dt.dtype_name(c_indices.dtype)
    if t_idx_dtype != c_idx_dtype:
        return False, f"indices dtype mismatch: torch={t_idx_dtype} c={c_idx_dtype}"
    t_idx_flat, c_idx_flat = _flatten_values(t_indices.tolist()), _flatten_values(c_indices.tolist())
    if t_idx_flat != c_idx_flat:
        return False, f"indices mismatch: torch={t_idx_flat!r} c={c_idx_flat!r}"
    return True, (
        f"values dtype={t_dtype} shape={t_shape}, "
        f"indices matched exactly (dtype={t_idx_dtype})"
    )


def _extremum_dim_cases(torch_module, c_module, torch_call, op, short) -> list[Case]:
    """`max.dim` and `min.dim` share every case, because they shared the bug.

    One builder rather than two, for the same reason `aten.rs` has one
    `extremum_dim`: the pair is generated from `torch_call`, which the harness
    resolves to `torch.ops.aten.<op>` on the upstream side, so the *expected*
    answers come from upstream separately for each and nothing is mirrored by
    hand here.
    """
    cases: list[Case] = []
    # Flat values chosen so the extremum is unique in every reduced slice --
    # ties are implementation-defined, same reasoning as argmax_cases above.
    scenarios = [
        dict(flat=[1, 5, 2, 9, 0, 3], shape=(2, 3), dim=1, keepdim=False, note="along last dim"),
        dict(flat=[1, 5, 2, 9, 0, 3], shape=(2, 3), dim=1, keepdim=True, note="along last dim, keepdim"),
        dict(flat=[1, 5, 2, 9, 0, 3], shape=(2, 3), dim=0, keepdim=False, note="along first dim"),
        dict(flat=[1, 5, 2, 9, 0, 3], shape=(2, 3), dim=-1, keepdim=False, note="dim=-1"),
        dict(flat=[-5, -1, -9, -3], shape=(2, 2), dim=1, keepdim=False, note="all-negative values"),
        dict(flat=[7], shape=(1,), dim=0, keepdim=False, note="single element"),
        dict(flat=list(range(24)), shape=(2, 3, 4), dim=2, keepdim=False, note="3D, innermost dim"),
        dict(flat=list(range(24)), shape=(2, 3, 4), dim=1, keepdim=False, note="3D, middle dim"),
        dict(flat=list(range(24)), shape=(2, 3, 4), dim=0, keepdim=True, note="3D, outermost dim, keepdim"),
    ]
    for dtype_name in _REDUCE_DTYPES:
        for sc in scenarios:
            a_t, a_c = pair_from_flat(torch_module, c_module, sc["flat"], sc["shape"], dtype_name)
            dim, keepdim = sc["dim"], sc["keepdim"]
            cases.append(
                Case(
                    name=f"{short}(dtype={dtype_name}, shape={sc['shape']}, dim={dim}, keepdim={keepdim}) [{sc['note']}]",
                    op=op,
                    run_torch=lambda a_t=a_t, dim=dim, keepdim=keepdim: torch_call(a_t, dim, keepdim),
                    run_c=lambda a_c=a_c, dim=dim, keepdim=keepdim: c_module._aten_dispatch(op, a_c, dim, keepdim),
                    value_check=_pair_result_check,
                    note=sc["note"] + " -- returns (values, indices), see _pair_result_check",
                )
            )

    # NaN, walked through every position -- the bug this builder was missing.
    #
    # Measured against upstream, not asserted from a rule: `max([1., nan, 3.],
    # dim=0)` is `(nan, 1)` and `min` of the same is `(nan, 1)` too. The value
    # is NaN because torch's rule is IEEE maximum/minimum, and the *index* is
    # the first NaN's rather than the extremum-among-the-rest's.
    #
    # This build answered `(3.0, 2)` for `max`, and `min.dim` had no kernel at
    # all. Both halves of the pair were wrong and they were wrong
    # *consistently* -- `c_values == c_input[c_indices]` held -- so a
    # self-consistency check would have passed. Only comparison against
    # upstream catches it, which is the whole argument for this harness.
    #
    # **Position matters and `at=0` is the one that cannot fail.** A NaN in
    # element 0 seeds candle's accumulator and nothing displaces it, so even a
    # kernel with no NaN handling gets `(nan, 0)` right. docs/SEQLEN.md §7.12
    # recorded the same hole in `amax`'s first test; the middle and last
    # positions are what make this a test.
    nan = float("nan")
    for at, where in [(0, "first"), (1, "middle"), (3, "last")]:
        flat = [1.0, 5.0, 2.0, 9.0]
        flat[at] = nan
        for dtype_name in ["float64", "float32", "float16", "bfloat16"]:
            for dim, keepdim in [(0, False), (0, True)]:
                a_t, a_c = pair_from_flat(torch_module, c_module, flat, (4,), dtype_name)
                note = (
                    f"NaN in the {where} position -- value propagates AND the index is "
                    f"the first NaN's, not the extremum-among-the-rest's"
                )
                cases.append(
                    Case(
                        name=f"{short}(dtype={dtype_name}, shape=(4,), dim={dim}, keepdim={keepdim}) [{note}]",
                        op=op,
                        run_torch=lambda a_t=a_t, dim=dim, keepdim=keepdim: torch_call(a_t, dim, keepdim),
                        run_c=lambda a_c=a_c, dim=dim, keepdim=keepdim: c_module._aten_dispatch(
                            op, a_c, dim, keepdim
                        ),
                        value_check=_pair_result_check,
                        note=note,
                    )
                )
    # Two NaNs -- pins the tie-break to the earlier index.
    # And a NaN confined to one row of two -- pins the correction as per-slice
    # rather than whole-tensor, which a `sum_all() > 0` guard applied to the
    # wrong scope would get wrong.
    extra = [
        ([1.0, nan, 2.0, nan], (4,), 0, "two NaNs -- the earlier index wins"),
        (
            [1.0, nan, 2.0, 4.0, 9.0, 3.0],
            (2, 3),
            1,
            "NaN in the first row only -- the second row keeps its ordinary answer",
        ),
        (
            [1.0, 2.0, nan, 4.0, 9.0, 3.0],
            (2, 3),
            0,
            "NaN in a strided (non-innermost) slice",
        ),
    ]
    for dtype_name in ["float64", "float32"]:
        for flat, shape, dim, note in extra:
            a_t, a_c = pair_from_flat(torch_module, c_module, flat, shape, dtype_name)
            cases.append(
                Case(
                    name=f"{short}(dtype={dtype_name}, shape={shape}, dim={dim}) [{note}]",
                    op=op,
                    run_torch=lambda a_t=a_t, dim=dim: torch_call(a_t, dim, False),
                    run_c=lambda a_c=a_c, dim=dim: c_module._aten_dispatch(op, a_c, dim, False),
                    value_check=_pair_result_check,
                    note=note,
                )
            )
    # `-inf` is not NaN and must not be corrected into one: an all-`-inf` row
    # is a fully masked attention row and its maximum is `-inf`. A correction
    # keyed on "not finite" rather than on "not equal to itself" passes every
    # NaN case above and fails this.
    ninf = float("-inf")
    for dtype_name in ["float64", "float32"]:
        for flat, note in [
            ([ninf] * 4, "an all -inf row -- a fully masked attention row"),
            ([ninf, ninf, -2.0, ninf], "-inf everywhere but one position"),
            ([float("inf"), 1.0, ninf, 2.0], "+inf and -inf together, no NaN"),
        ]:
            a_t, a_c = pair_from_flat(torch_module, c_module, flat, (4,), dtype_name)
            cases.append(
                Case(
                    name=f"{short}(dtype={dtype_name}, shape=(4,), dim=0) [{note}]",
                    op=op,
                    run_torch=lambda a_t=a_t: torch_call(a_t, 0, False),
                    run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, 0, False),
                    value_check=_pair_result_check,
                    note=note,
                )
            )
    return cases


def max_dim_cases(torch_module, c_module, torch_call) -> list[Case]:
    return _extremum_dim_cases(torch_module, c_module, torch_call, "aten.max.dim", "max")


# --- aten.min.dim -------------------------------------------------------------
#
# A new kernel, not a promotion. docs/SPELLINGS.md §7.2 found that `min.dim`
# and `min.other` were listed in `overloads.json`/`methods.json` with **no
# kernel behind either** -- deliberately, so `torch.min(x, dim=0)` would refuse
# by name rather than be silently absent, and so the next owner of `aten.rs`
# would find a precise work item. docs/TRIL.md §3 is that owner. Both now
# compute, both share their implementation with the `max` side, and both share
# these cases with it -- including the NaN walk, which is the reason they were
# written together rather than the `min` half being added as a copy.


def min_dim_cases(torch_module, c_module, torch_call) -> list[Case]:
    return _extremum_dim_cases(torch_module, c_module, torch_call, "aten.min.dim", "min")


# --- aten.max.other -----------------------------------------------------------
#
# Moved out of `IMPLEMENTED_AWAITING_GOLDEN` by this builder (docs/SPELLINGS.md):
# the kernel already existed and `_aten_dispatch("aten.max.other", ...)` already
# computed, but nothing in this file compared it against upstream. `torch_call`
# resolves `torch.ops.aten.max.other` directly -- the real ATen op, which
# `native_functions.yaml` documents as "binary max, alias of maximum" -- so this
# checks the kernel's *values* regardless of which op name `torch.max(a, b)`'s
# own Python frontend happens to redirect to (measured: `aten::maximum`, not
# `max.other` -- see the `overloads.json` README note on `max` for why the
# table still spells the free function through this op).


def _extremum_other_cases(torch_module, c_module, torch_call, op, short) -> list[Case]:
    cases: list[Case] = []
    for dtype_name in _REDUCE_DTYPES:
        for sc in _ELEMENTWISE_SCENARIOS:
            cases.append(
                _binary_tensor_case(
                    torch_module, c_module, op, torch_call, dtype_name,
                    sc["a_flat"], sc["a_shape"], sc["b_flat"], sc["b_shape"], sc["note"],
                )
            )
    # Every element tied, so the case is only useful if the kernel actually
    # picks *a* correct value rather than, say, one operand unconditionally.
    cases.append(
        _binary_tensor_case(
            torch_module, c_module, op, torch_call, "int64",
            [3, 3, 3], (3,), [3, 3, 3], (3,), "every element tied",
        )
    )
    # NaN propagation -- the same rule `max_default_cases` pins for the
    # reduction overload, but not a duplicate of it: this is a different kernel
    # (elementwise two-tensor vs. single-tensor reduction) and it had a
    # different, *asymmetric* fault. `aten::maximum`/`aten::minimum` (which
    # `native_functions.yaml` names these as aliases of) are IEEE
    # maximum/minimum -- a NaN on either side wins.
    #
    # docs/SPELLINGS.md §7.2 added the first of these while the op was parked
    # in `IMPLEMENTED_AWAITING_GOLDEN`, and it recorded a live defect rather
    # than passing: `max.other([1,nan,3], [5,2,nan])` gave `[5, nan, 3]` here
    # against upstream's `[5, nan, nan]`, and `max.other([1],[nan])` gave `[1]`
    # against `[nan]`. A NaN in the *first* operand propagated correctly
    # because candle's `|x, y| x > y` never displaces an accumulator that
    # already holds one; a NaN only in the second was skipped. docs/TRIL.md §3
    # is the fix, and the op is promoted into `_aten_implemented()` in the same
    # change -- so these now run in the main `compare.py` gate.
    #
    # **Every position, on both sides, and the broadcast case separately.** A
    # correction that masks by the left operand's NaNs alone passes the `a`
    # column; one that forgets to broadcast the mask passes every same-shape
    # case and fails only the last two.
    nan = float("nan")
    nan_pairs = [
        ([1.0, nan, 3.0], (3,), [5.0, 2.0, nan], (3,), "NaN in each operand, different positions"),
        ([nan, 2.0, 3.0], (3,), [5.0, 2.0, 1.0], (3,), "NaN only in the first operand, first position"),
        ([1.0, 2.0, nan], (3,), [5.0, 2.0, 1.0], (3,), "NaN only in the first operand, last position"),
        ([1.0, 2.0, 3.0], (3,), [nan, 2.0, 1.0], (3,), "NaN only in the second operand, first position"),
        ([1.0, 2.0, 3.0], (3,), [5.0, nan, 1.0], (3,), "NaN only in the second operand, middle position"),
        ([1.0, 2.0, 3.0], (3,), [5.0, 2.0, nan], (3,), "NaN only in the second operand, last position"),
        ([nan, nan, nan], (3,), [5.0, 2.0, 1.0], (3,), "every element of the first operand NaN"),
        ([1.0], (1,), [nan], (1,), "one element each, NaN in the second"),
        ([1.0, 2.0], (2,), [nan], (), "0-d NaN broadcast over both elements"),
        ([nan], (), [1.0, 2.0], (2,), "0-d NaN in the first operand, broadcast"),
    ]
    for dtype_name in ["float64", "float32", "float16", "bfloat16"]:
        for a_flat, a_shape, b_flat, b_shape, note in nan_pairs:
            cases.append(
                _binary_tensor_case(
                    torch_module, c_module, op, torch_call, dtype_name,
                    a_flat, a_shape, b_flat, b_shape, note,
                )
            )
    # `inf` is ordered, not NaN: a correction keyed on "not finite" would turn
    # these into NaN and fail here while passing every case above.
    ninf, pinf = float("-inf"), float("inf")
    for dtype_name in ["float64", "float32"]:
        cases.append(
            _binary_tensor_case(
                torch_module, c_module, op, torch_call, dtype_name,
                [pinf, ninf, 1.0], (3,), [1.0, 1.0, ninf], (3,),
                "infinities on both sides and no NaN -- must not be corrected into NaN",
            )
        )
    return cases


def max_other_cases(torch_module, c_module, torch_call) -> list[Case]:
    return _extremum_other_cases(torch_module, c_module, torch_call, "aten.max.other", "max")


# --- aten.min.other -----------------------------------------------------------
#
# The `min` half of the same story as `min.dim` above: listed in the spelling
# tables with no kernel, implemented in docs/TRIL.md §3 as one function with
# `max.other`, and sharing this builder for the same reason. `torch_call`
# resolves `torch.ops.aten.min.other` on the upstream side, so the expected
# values are upstream's own and nothing here is mirrored by hand.


def min_other_cases(torch_module, c_module, torch_call) -> list[Case]:
    return _extremum_other_cases(torch_module, c_module, torch_call, "aten.min.other", "min")


# --- aten.tril.default / aten.triu.default ------------------------------------
#
# GPT-BigCode's last wall (docs/TORCHSCRIPT.md §6) and its mirror.
#
# The `nan`/`inf` matrix below is the case with a job: the tempting
# implementation is a 0/1 mask of the input's dtype and a broadcast multiply,
# and `nan * 0` is `nan` while upstream zeroes that position like any other.
# Every case built from small integers passes under that mistake.
#
# The `diagonal` sweep runs past the matrix in both directions (`|d| > n`)
# because the offset is unbounded upstream -- `tril(x, 100)` is `x` -- and an
# implementation that clamped or indexed with it would fault or truncate.


def _triangle_cases(torch_module, c_module, torch_call, op, short) -> list[Case]:
    cases: list[Case] = []
    nan, pinf, ninf = float("nan"), float("inf"), float("-inf")

    # Square, non-square both ways, and batched. Values are all distinct so a
    # transposed or mis-broadcast mask cannot coincidentally agree.
    shapes = [
        (list(range(1, 10)), (3, 3), "3x3 square"),
        (list(range(1, 9)), (2, 4), "2x4, wider than tall"),
        (list(range(1, 9)), (4, 2), "4x2, taller than wide"),
        (list(range(1, 2)), (1, 1), "1x1"),
        (list(range(1, 5)), (1, 4), "single row"),
        (list(range(1, 5)), (4, 1), "single column"),
        (list(range(24)), (2, 3, 4), "batched: two 3x4 matrices"),
        (list(range(24)), (2, 2, 3, 2), "batched rank 4"),
    ]
    for dtype_name in ["float64", "float32", "float16", "bfloat16", "int64", "int32"]:
        for flat, shape, note in shapes:
            for diagonal in (-4, -1, 0, 1, 4):
                a_t, a_c = pair_from_flat(torch_module, c_module, flat, shape, dtype_name)
                full = f"{note}, diagonal={diagonal}"
                cases.append(
                    Case(
                        name=f"{short}(dtype={dtype_name}, shape={shape}, diagonal={diagonal}) [{note}]",
                        op=op,
                        run_torch=lambda a_t=a_t, d=diagonal: torch_call(a_t, d),
                        run_c=lambda a_c=a_c, d=diagonal: c_module._aten_dispatch(op, a_c, d),
                        note=full,
                    )
                )

    # The default `diagonal`, omitted entirely rather than passed as 0 -- the
    # schema's default has to be applied by the kernel, not by the caller.
    for dtype_name in ["float32", "int64"]:
        a_t, a_c = pair_from_flat(torch_module, c_module, list(range(1, 10)), (3, 3), dtype_name)
        cases.append(
            Case(
                name=f"{short}(dtype={dtype_name}, shape=(3, 3)) [diagonal defaulted, not passed]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c),
                note="diagonal omitted -- the schema default is 0",
            )
        )
    # ...and by keyword.
    a_t, a_c = pair_from_flat(torch_module, c_module, list(range(1, 10)), (3, 3), "float32")
    cases.append(
        Case(
            name=f"{short}(self=/diagonal= by keyword)",
            op=op,
            run_torch=lambda: torch_call(self=a_t, diagonal=1),
            run_c=lambda: c_module._aten_dispatch(op, self=a_c, diagonal=1),
        )
    )

    # `torch.bool` -- GPT-BigCode's actual call is
    # `tril(ones((n, n), dtype=bool))`, and the result must stay `bool` rather
    # than being promoted by the zeroing.
    for flat, shape, note in [
        ([1, 1, 1, 1, 1, 1, 1, 1, 1], (3, 3), "all-True bool mask, GPT-BigCode's own call"),
        ([1, 0, 1, 0, 1, 0, 1, 0, 1], (3, 3), "mixed bool"),
    ]:
        for diagonal in (-1, 0, 1):
            a_t, a_c = pair_from_flat(torch_module, c_module, flat, shape, "bool")
            cases.append(
                Case(
                    name=f"{short}(dtype=bool, shape={shape}, diagonal={diagonal}) [{note}]",
                    op=op,
                    run_torch=lambda a_t=a_t, d=diagonal: torch_call(a_t, d),
                    run_c=lambda a_c=a_c, d=diagonal: c_module._aten_dispatch(op, a_c, d),
                    note=note,
                )
            )

    # The case a masked multiply cannot pass.
    for dtype_name in ["float64", "float32"]:
        for diagonal in (-1, 0, 1):
            a_t, a_c = pair_from_flat(
                torch_module, c_module,
                [1.0, nan, pinf, ninf, nan, 2.0, ninf, pinf, 0.0], (3, 3), dtype_name,
            )
            note = "nan/inf matrix -- zeroing must be a select; nan*0 and inf*0 are nan"
            cases.append(
                Case(
                    name=f"{short}(dtype={dtype_name}, shape=(3, 3), diagonal={diagonal}) [{note}]",
                    op=op,
                    run_torch=lambda a_t=a_t, d=diagonal: torch_call(a_t, d),
                    run_c=lambda a_c=a_c, d=diagonal: c_module._aten_dispatch(op, a_c, d),
                    note=note,
                )
            )

    # Zero-extent inputs, both ways round. Upstream preserves the shape.
    for shape in [(0, 3), (3, 0), (0, 0), (2, 0, 3)]:
        a_t, a_c = pair_from_flat(torch_module, c_module, [], shape, "float32")
        cases.append(
            Case(
                name=f"{short}(dtype=float32, shape={shape}) [zero-extent, shape preserved]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, 0),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, 0),
                note="zero-extent input",
            )
        )

    # Rank < 2 is refused on both sides, with upstream's own wording.
    for flat, shape, note in [([1.0], (), "0-d"), ([1.0, 2.0], (2,), "1-d")]:
        a_t, a_c = pair_from_flat(torch_module, c_module, flat, shape, "float32")
        cases.append(
            Case(
                name=f"{short}(dtype=float32, shape={shape}) [{note} -- refused, needs 2 dimensions]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, 0),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, 0),
                expect="both_error",
                note=note,
            )
        )
    return cases


def tril_cases(torch_module, c_module, torch_call) -> list[Case]:
    return _triangle_cases(torch_module, c_module, torch_call, "aten.tril.default", "tril")


def triu_cases(torch_module, c_module, torch_call) -> list[Case]:
    return _triangle_cases(torch_module, c_module, torch_call, "aten.triu.default", "triu")


# --- aten.reshape.default ------------------------------------------------------
#
# Also moved out of `IMPLEMENTED_AWAITING_GOLDEN` by this builder
# (docs/SPELLINGS.md). Unlike `view.default` above, this shim's `reshape`
# kernel is not a thin alias: `_install_tensor_views`'s `flatten` composite
# calls `dispatch("aten.reshape.default", ...)` specifically because the real
# kernel already carries both of upstream's two decomposition arms -- return a
# view when the input is contiguous, copy when it is not -- so the case below
# that starts from a transposed (non-contiguous) view is not decoration, it is
# the one input `view_cases` above explicitly calls out as outside its own
# granularity ("reshape()'s non-contiguous fallback ... is a different op
# pair"). `torch_call` resolves `torch.ops.aten.reshape.default` directly,
# which runs upstream's own composite body and returns a real value to diff
# against, not just a schema.


def reshape_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.reshape.default"
    cases: list[Case] = []
    for dtype_name in ["float64", "float32", "int64", "uint8"]:
        a_t, a_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4, 5, 6], (2, 3), dtype_name)
        cases.append(
            Case(
                name=f"reshape(dtype={dtype_name}, (2,3)->(6,)) [contiguous -- view arm]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, [6]),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, [6]),
                note="contiguous input takes reshape's view arm",
            )
        )
        cases.append(
            Case(
                name=f"reshape(dtype={dtype_name}, (2,3)->(-1,)) [inferred dim]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, [-1]),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, [-1]),
                note="-1 means 'infer this dim's size'",
            )
        )

        # Non-contiguous input (a transposed view) -- reshape's copy arm.
        base_t, base_c = pair_from_flat(torch_module, c_module, list(range(12)), (3, 4), dtype_name)
        nc_t = base_t.t()
        nc_c = c_module._aten_dispatch("aten.t.default", base_c)
        cases.append(
            Case(
                name=f"reshape(dtype={dtype_name}, (3,4).t()->(12,)) [non-contiguous -- copy arm]",
                op=op,
                run_torch=lambda nc_t=nc_t: torch_call(nc_t, [12]),
                run_c=lambda nc_c=nc_c: c_module._aten_dispatch(op, nc_c, [12]),
                note=(
                    "a transposed view is not contiguous, so upstream's own "
                    "reshape composite copies here instead of viewing -- this is "
                    "the arm view_cases' module note says is out of its scope"
                ),
            )
        )
    # 0-d -> [1]: the same edge `_install_tensor_views::flatten` uses reshape
    # for on a scalar tensor (docs/ARCH20.md §5's cohere note).
    zerod_t, zerod_c = pair_from_flat(torch_module, c_module, [7.0], (), "float32")
    cases.append(
        Case(
            name="reshape(dtype=float32, ()->[1]) [0-d -- flatten()'s own call shape]",
            op=op,
            run_torch=lambda: torch_call(zerod_t, [1]),
            run_c=lambda: c_module._aten_dispatch(op, zerod_c, [1]),
            note="0-d is not a no-op: shape becomes (1,)",
        )
    )
    return cases


# --- aten.mean.default / aten.mean.dim / aten.sum.default / aten.sum.dim_IntList --

def mean_default_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.mean.default"
    cases: list[Case] = []
    for dtype_name in _MUL_DIV_FLOAT_DTYPES:
        for flat, shape, note in [
            ([1.0, 2.0, 3.0, 4.0, 5.0, 6.0], (2, 3), "global mean, flattened"),
            ([-2.0, 2.0], (2,), "symmetric around zero -> 0"),
            ([5.0], (), "0-d"),
        ]:
            cases.append(_unary_case(torch_module, c_module, op, torch_call, dtype_name, flat, shape, note))
    return cases


def mean_dim_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.mean.dim"
    cases: list[Case] = []
    for dtype_name in _MUL_DIV_FLOAT_DTYPES:
        a_t, a_c = pair_from_flat(torch_module, c_module, [1.0, 2.0, 3.0, 4.0, 5.0, 6.0], (2, 3), dtype_name)
        for dim, keepdim, note in [
            ([-1], True, "RMSNorm-style: reduce last dim, keepdim"),
            ([0], False, "reduce first dim"),
            (None, False, "dim=None -- reduce all"),
            # An empty `dim` list is not the same as `dim=None`: torch
            # documents it as reducing *every* dimension too, but it is a
            # distinct code path (`sum.dim_IntList`/`mean.dim` vs
            # `sum.default`/`mean.default`) and this shim's kernel used to
            # take the empty list literally -- "reduce over these zero
            # axes" -- and hand the input back unchanged. Measured against
            # upstream torch 2.13.0 (not copied from a doc comment):
            # torch.mean(ones(3,4), dim=[]) -> shape (), value 1.0.
            ([], False, "dim=[] -- reduce all (empty dim list, not dim=None)"),
            ([], True, "dim=[] keepdim=True -- reduce all, every axis kept at size 1"),
            ([0, 1], False, "dim=[0,1] -- explicit reduce of every axis"),
        ]:
            cases.append(
                Case(
                    name=f"mean(dtype={dtype_name}, dim={dim}, keepdim={keepdim}) [{note}]",
                    op=op,
                    run_torch=lambda a_t=a_t, dim=dim, keepdim=keepdim: torch_call(a_t, dim, keepdim),
                    run_c=lambda a_c=a_c, dim=dim, keepdim=keepdim: c_module._aten_dispatch(op, a_c, dim, keepdim),
                    note=note,
                )
            )
        # torch refuses a repeated dim ("dim 0 appears multiple times in
        # the list of dims"); measured against upstream 2.13.0.
        cases.append(
            Case(
                name=f"mean(dtype={dtype_name}, dim=[0, 0], keepdim=False) [duplicate dim]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, [0, 0], False),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, [0, 0], False),
                expect="both_error",
                note="duplicate dim index -- both sides must refuse",
            )
        )
    cases.extend(_reduced_float_reduce_cases(torch_module, c_module, op, torch_call))
    return cases


def sum_default_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.sum.default"
    cases: list[Case] = []
    for dtype_name in _REDUCE_DTYPES:
        for flat, shape, note in [
            ([1, 2, 3, 4, 5, 6], (2, 3), "global sum, flattened"),
            ([-2, 2], (2,), "cancelling values -> 0"),
            ([7], (), "0-d"),
        ]:
            cases.append(_unary_case(torch_module, c_module, op, torch_call, dtype_name, flat, shape, note))
    return cases


def sum_dim_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.sum.dim_IntList"
    cases: list[Case] = []
    for dtype_name in _REDUCE_DTYPES:
        a_t, a_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4, 5, 6], (2, 3), dtype_name)
        for dim, keepdim, note in [
            ([-1], True, "reduce last dim, keepdim"),
            ([0], False, "reduce first dim"),
            (None, False, "dim=None -- reduce all"),
            # docs/DECOMP.md §6.1: the decomposition pass rewrites
            # `sum(x)` to `sum(x, dim=[], dtype=None)`, and nothing had
            # ever exercised an empty `dim` list before that pass existed
            # -- this shim's kernel took it literally as "reduce over
            # these zero axes" and returned the input unchanged instead of
            # reducing every dimension. Measured against upstream torch
            # 2.13.0, not copied from the bug report:
            # torch.sum(ones(3,4), dim=[]) -> shape (), value 12.0.
            ([], False, "dim=[] -- reduce all (empty dim list, not dim=None)"),
            ([], True, "dim=[] keepdim=True -- reduce all, every axis kept at size 1"),
            ([0, 1], False, "dim=[0,1] -- explicit reduce of every axis"),
        ]:
            cases.append(
                Case(
                    name=f"sum(dtype={dtype_name}, dim={dim}, keepdim={keepdim}) [{note}]",
                    op=op,
                    run_torch=lambda a_t=a_t, dim=dim, keepdim=keepdim: torch_call(a_t, dim, keepdim),
                    run_c=lambda a_c=a_c, dim=dim, keepdim=keepdim: c_module._aten_dispatch(op, a_c, dim, keepdim),
                    note=note,
                )
            )
        # torch refuses a repeated dim ("dim 0 appears multiple times in
        # the list of dims"); measured against upstream 2.13.0. Candle
        # already refuses too (`sum: duplicate dim index`), so this is a
        # regression pin, not a fix.
        cases.append(
            Case(
                name=f"sum(dtype={dtype_name}, dim=[0, 0], keepdim=False) [duplicate dim]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, [0, 0], False),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, [0, 0], False),
                expect="both_error",
                note="duplicate dim index -- both sides must refuse",
            )
        )
    cases.extend(_reduced_float_reduce_cases(torch_module, c_module, op, torch_call))
    return cases


# --- aten.new_ones.default ----------------------------------------------------

def new_ones_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.new_ones.default"
    cases: list[Case] = []
    for self_dtype in ["float64", "float32", "int64", "uint8"]:
        a_t, a_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (2, 2), self_dtype)
        cases.append(
            Case(
                name=f"new_ones(self_dtype={self_dtype}, shape=[2,3]) [dtype inherited from self]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, [2, 3]),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, [2, 3]),
                note="dtype inherited from the self tensor, not a default",
            )
        )
    for dtype_name in dt.DEFAULT_DTYPES:
        t_dt = dt.torch_dtype(torch_module, dtype_name)
        c_dt = dt.c_dtype(c_module, dtype_name)
        a_t, a_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (2, 2), "float32")
        cases.append(
            Case(
                name=f"new_ones(self_dtype=float32, shape=[2,2], dtype_override={dtype_name})",
                op=op,
                run_torch=lambda a_t=a_t, t_dt=t_dt: torch_call(a_t, [2, 2], dtype=t_dt),
                run_c=lambda a_c=a_c, c_dt=c_dt: c_module._aten_dispatch(op, a_c, [2, 2], dtype=c_dt),
                note="explicit dtype override beats the self tensor's dtype",
            )
        )
    return cases


# --- aten.transpose.int / aten.unsqueeze.default / aten.view.default -------

def transpose_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.transpose.int"
    cases: list[Case] = []
    for dtype_name in ["float64", "float32", "int64", "uint8"]:
        a_t, a_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4, 5, 6], (2, 3), dtype_name)
        cases.append(
            Case(
                name=f"transpose(dtype={dtype_name}, dim0=0, dim1=1)",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, 0, 1),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, 0, 1),
                note="swap the two axes of a 2D tensor",
            )
        )
        cases.append(
            Case(
                name=f"transpose(dtype={dtype_name}, dim0=-2, dim1=-1)",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, -2, -1),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, -2, -1),
                note="negative dims, as in attention's q @ k.transpose(-2, -1)",
            )
        )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # self/dim0/dim1 all by keyword -- DISPATCH.md's own microbench example op.
    kw_t, kw_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4, 5, 6], (2, 3), "float32")
    cases.append(
        Case(
            name="transpose(self=/dim0=/dim1= all by keyword)",
            op=op,
            run_torch=lambda: torch_call(self=kw_t, dim0=0, dim1=1),
            run_c=lambda: c_module._aten_dispatch(op, self=kw_c, dim0=0, dim1=1),
        )
    )
    return cases


def unsqueeze_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.unsqueeze.default"
    cases: list[Case] = []
    for dtype_name in ["float64", "float32", "int64", "uint8"]:
        a_t, a_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (4,), dtype_name)
        for dim, note in [(0, "prepend a new axis"), (-1, "append a new axis (negative dim)"), (1, "insert in the middle")]:
            cases.append(
                Case(
                    name=f"unsqueeze(dtype={dtype_name}, dim={dim}) [{note}]",
                    op=op,
                    run_torch=lambda a_t=a_t, dim=dim: torch_call(a_t, dim),
                    run_c=lambda a_c=a_c, dim=dim: c_module._aten_dispatch(op, a_c, dim),
                    note=note,
                )
            )
    return cases


def view_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.view.default"
    cases: list[Case] = []
    for dtype_name in ["float64", "float32", "float16", "bfloat16", "int64", "int32", "uint8"]:
        a_t, a_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4, 5, 6], (2, 3), dtype_name)
        cases.append(
            Case(
                name=f"view(dtype={dtype_name}, (2,3)->(6,)) [also backs reshape() on a contiguous input]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, [6]),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, [6]),
                note=(
                    "flatten -- reshape()'s non-contiguous fallback (clone + "
                    "_unsafe_view) is a different op pair, outside this harness's "
                    "per-op comparison granularity; see the module note above."
                ),
            )
        )
        cases.append(
            Case(
                name=f"view(dtype={dtype_name}, (2,3)->(3,2))",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, [3, 2]),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, [3, 2]),
                note="reshape to a different rank-2 shape",
            )
        )
        cases.append(
            Case(
                name=f"view(dtype={dtype_name}, (2,3)->(-1,)) [inferred dim]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, [-1]),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, [-1]),
                note="-1 means 'infer this dim's size'",
            )
        )
    return cases


# --- aten.view.dtype ----------------------------------------------------------
# The bit-reinterpreting `view`, which is *not* a cast: `1.0` viewed as int32 is
# 1065353216, not 1. It is how safetensors' default backend spells a
# checkpoint's dtype (docs/CKPT2.md §4), and the reason it needs comparing
# against upstream rather than reasoning about is that every one of its answers
# is a bit pattern -- an implementation that quietly converted instead of
# reinterpreting would produce clean, plausible, wrong numbers.

def view_dtype_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.view.dtype"
    cases: list[Case] = []
    # Widths 1/2/4/8 in both directions, so the last-dim arithmetic is checked
    # narrowing and widening, plus same-width pairs where no shape changes.
    plans = [
        ("uint8", (24,), "float32", "the safetensors shape: bytes become floats"),
        ("uint8", (2, 12), "float32", "only the last dim takes part"),
        ("uint8", (2, 3, 4), "float32", "rank 3, last dim exactly one element wide"),
        ("uint8", (16,), "int64", "widest widening this build can hold"),
        ("float32", (6,), "uint8", "narrowing: each float becomes four bytes"),
        ("float32", (6,), "int32", "same width, different family -- the bits, not the value"),
        ("float32", (6,), "float64", "widening between floats"),
        ("int64", (3,), "int16", "narrowing between integers"),
        ("int32", (4,), "float32", "same width, integer to float"),
        ("uint8", (0,), "float32", "empty is not an error upstream"),
    ]
    for src, shape, dst, note in plans:
        numel = 1
        for d in shape:
            numel *= d
        # Values chosen so consecutive elements differ: a kernel that returned
        # the right shape but read from the wrong offset could otherwise pass
        # on a buffer of repeated bytes.
        flat = [(i * 7 + 1) % 251 for i in range(numel)]
        a_t, a_c = pair_from_flat(torch_module, c_module, flat, shape, src)
        t_dt = dt.torch_dtype(torch_module, dst)
        c_dt = dt.c_dtype(c_module, dst)
        cases.append(
            Case(
                name=f"view.dtype({src}{tuple(shape)} -> {dst})",
                op=op,
                run_torch=lambda a_t=a_t, t_dt=t_dt: torch_call(a_t, t_dt),
                run_c=lambda a_c=a_c, c_dt=c_dt: c_module._aten_dispatch(op, a_c, c_dt),
                note=note,
            )
        )

    # **The second of the two aliasing relationships still disagreeing with
    # upstream** (the other is a step > 1 `slice.Tensor`, in `slice_cases`).
    #
    # Upstream's `view.dtype` is a genuine view: the same bytes, reinterpreted,
    # so writing through the result reaches the input. Here it goes out through
    # `to_le_bytes` and back in through `from_le_bytes`, which allocates -- and
    # it *has* to, because candle's `Layout` is measured in elements of a
    # storage whose dtype is fixed. There is no reinterpreting Layout to build,
    # publicly or privately, so this is a property of candle's storage model
    # rather than of its visibility rules. docs/VIEWS.md §6.4.
    #
    # Recorded rather than fixed, and recorded as a `diverge` so it fails if it
    # ever starts agreeing without this note being updated.
    def _view_dtype_write(is_torch, base):
        if is_torch:
            view = torch_call(base, torch_module.float32)
            torch_module.ops.aten.fill_.Scalar(view, 0.0)
        else:
            view = c_module._aten_dispatch(op, base, c_module.float32)
            c_module._aten_dispatch("aten.fill_.Scalar", view, 0.0)
        return base

    cases.append(
        Case(
            name="base after fill_(x.view(float32), 0.0) [reads the BASE] -- a copy here",
            op=op,
            run_torch=lambda: _view_dtype_write(
                True, torch_module.tensor([1, 2, 3, 4], dtype=torch_module.int32)),
            run_c=lambda: _view_dtype_write(
                False, c_module._tensor_from_flat([1, 2, 3, 4], [4], dtype=c_module.int32)),
            expect="diverge",
            note="view.dtype aliases upstream and reinterprets through a byte round-trip "
                 "here, so the write reaches the base upstream ([0,0,0,0]) and is lost "
                 "here ([1,2,3,4]). candle's Layout counts elements of a fixed-dtype "
                 "storage -- docs/VIEWS.md §6.4",
        )
    )
    return cases


# --- aten._to_copy.default ----------------------------------------------------
# `float()`, `long()`, `to(dtype)` all dispatch to the same cast op.

def to_copy_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten._to_copy.default"
    cases: list[Case] = []
    conversions = [
        ("int64", "float32", "backs .float()"),
        ("float32", "int64", "backs .long()"),
        ("float32", "float64", "backs .to(dtype) upcast"),
        ("float64", "float32", "backs .to(dtype) downcast"),
        ("float32", "float16", "backs .to(dtype), precision loss"),
        ("int32", "int64", "backs .to(dtype), int widening"),
        ("uint8", "float32", "backs .to(dtype), unsigned to float"),
    ]
    for src_dtype, dst_dtype, note in conversions:
        a_t, a_c = pair_from_flat(torch_module, c_module, [0, 1, 2, 3], (2, 2), src_dtype)
        t_dt = dt.torch_dtype(torch_module, dst_dtype)
        c_dt = dt.c_dtype(c_module, dst_dtype)
        cases.append(
            Case(
                name=f"_to_copy({src_dtype} -> {dst_dtype}) [{note}]",
                op=op,
                run_torch=lambda a_t=a_t, t_dt=t_dt: torch_call(a_t, dtype=t_dt),
                run_c=lambda a_c=a_c, c_dt=c_dt: c_module._aten_dispatch(op, a_c, dtype=c_dt),
                note=note,
            )
        )

    # **`_to_copy` must copy even when there is nothing to convert**, and the
    # only way to ask is to write into the result and read the *input*.
    #
    # This case exists because its absence was measured. `to_device` and
    # `fast_to` both return `self.clone()` when the dtype and device already
    # match, and a candle clone is an `Arc` clone -- so `x.to(torch.float32)`
    # on a float32 tensor handed back an alias. Deleting the `Tensor::copy()`
    # that fixes it left the whole suite at 3069/3069 and all 228 smoke tests
    # green: every existing case compares the op's *result*, and the result was
    # right. Only reading the input afterwards can fail.
    #
    # It is the sharpest defect write-through can produce, because it is a
    # corruption rather than a lost write: upstream leaves `x` alone.
    # docs/VIEWS.md §6.3.
    for dtype_name in ["float32", "int64"]:
        def _write_through_result(is_torch, base, dtype_name=dtype_name):
            if is_torch:
                out = torch_call(base, dtype=dt.torch_dtype(torch_module, dtype_name))
                torch_module.ops.aten.fill_.Scalar(out, 0)
            else:
                out = c_module._aten_dispatch(op, base, dtype=dt.c_dtype(c_module, dtype_name))
                c_module._aten_dispatch("aten.fill_.Scalar", out, 0)
            return base

        cases.append(
            Case(
                name=f"input after fill_(x.to({dtype_name}), 0) with NOTHING to convert "
                     f"[reads the INPUT]",
                op=op,
                run_torch=lambda dtype_name=dtype_name, f=_write_through_result: f(
                    True, torch_module.tensor(
                        [1, 2, 3, 4], dtype=dt.torch_dtype(torch_module, dtype_name)
                    ).reshape([2, 2])),
                run_c=lambda dtype_name=dtype_name, f=_write_through_result: f(
                    False, c_module._tensor_from_flat(
                        [1, 2, 3, 4], [2, 2], dtype=dt.c_dtype(c_module, dtype_name))),
                note="_to_copy is named for the copy; a no-op conversion that aliased "
                     "would let a write into the result corrupt the input",
            )
        )
    return cases


# --- in-place methods: aten.fill_.Scalar / aten.copy_.default / -------------
# aten.normal_.default / aten.uniform_.default
#
# See the module note above on why in-place cases build a fresh operand
# pair per case rather than sharing one across cases.

def fill__cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.fill_.Scalar"
    cases: list[Case] = []
    # Reuses the fill-value/boundary table from full_cases above for
    # dtype/boundary coverage parity between "construct filled" (full) and
    # "fill in place" (fill_) -- including its two live regression traps
    # (the float16-overflow and int32-overflow entries). Those are still
    # `expect="match"` in the table itself (never `"c_error"`, per
    # full_cases' own docstring), and a probe against real torch confirmed
    # `fill_.Scalar` refuses the same overflowing values `full.default`
    # does (`RuntimeError: value cannot be converted to type ... without
    # overflow`) -- so the same trap applies here unchanged: this stays
    # `expect="match"` and will only fail if `_C`'s eventual fill_ silently
    # computes instead of refusing, exactly like the original trap's intent.
    # `expect != "match"` guards against `_FULL_FILLS` growing a non-match
    # entry later; it is a no-op today since every current entry is "match".
    for dtype_name in dt.DEFAULT_DTYPES:
        for fill, expect, note in _FULL_FILLS[dtype_name]:
            if expect != "match":
                continue
            a_t, a_c = pair_from_flat(torch_module, c_module, [0, 0, 0, 0], (2, 2), dtype_name)
            cases.append(
                Case(
                    name=f"fill_(dtype={dtype_name}, value={fill!r})",
                    op=op,
                    run_torch=lambda a_t=a_t, fill=fill: torch_call(a_t, fill),
                    run_c=lambda a_c=a_c, fill=fill: c_module._aten_dispatch(op, a_c, fill),
                    note=(note or "in-place fill") + " -- compares the mutated operand fill_ returns",
                )
            )
    cases.extend(
        c for c in _view_write_cases(torch_module, c_module)
        if c.op == "aten.fill_.Scalar"
    )
    return cases


def copy__cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.copy_.default"
    cases: list[Case] = []
    for dtype_name in ["float64", "float32", "float16", "bfloat16", "int64", "int32", "uint8"]:
        dst_t, dst_c = pair_from_flat(torch_module, c_module, [0, 0, 0, 0], (2, 2), dtype_name)
        src_t, src_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (2, 2), dtype_name)
        cases.append(
            Case(
                name=f"copy_(dtype={dtype_name}, same shape)",
                op=op,
                run_torch=lambda dst_t=dst_t, src_t=src_t: torch_call(dst_t, src_t),
                run_c=lambda dst_c=dst_c, src_c=src_c: c_module._aten_dispatch(op, dst_c, src_c),
                note="in-place: compares the mutated dst operand copy_ returns",
            )
        )
    dst2_t, dst2_c = pair_from_flat(torch_module, c_module, [0, 0, 0, 0], (2, 2), "float32")
    src2_t, src2_c = pair_from_flat(torch_module, c_module, [9, 8], (1, 2), "float32")
    cases.append(
        Case(
            name="copy_(dtype=float32, broadcast src)",
            op=op,
            run_torch=lambda: torch_call(dst2_t, src2_t),
            run_c=lambda: c_module._aten_dispatch(op, dst2_c, src2_c),
            note="src (1,2) broadcasts to fill dst (2,2) in place",
        )
    )
    cases.extend(
        c for c in _setitem_member_cases(torch_module, c_module)
        if c.op == "aten.copy_.default"
    )
    cases.extend(
        c for c in _view_write_cases(torch_module, c_module)
        if c.op == "aten.copy_.default"
    )
    return cases


# The RNG ops' streams are the SAME stream, and these two builders say so.
#
# When they were written, `_C` drew from candle and the module note above was
# right: two independent generators cannot be lined up by a seed. docs/RNG.md
# then established that candle's CPU backend *refuses* to be seeded at all, so
# there was no version of that plan, and torch's own CPU generator was ported
# into `rust/torch_c/src/rng.rs` instead. That makes the seed mean the same
# thing on both sides, and these cases were promoted off `_range_check` to say
# so: seed both generators to the same value inside the run lambdas, then
# compare the draws **element by element**.
#
# What each op may be held to is not the same, and docs/RNG.md §3.3 and §5
# item 3 are the authority for the split:
#
#   * `uniform_` is a masked integer times a power-of-two divisor and an
#     affine step. No libm, no vector specialisation, so **bit-for-bit on
#     every platform**.
#   * `normal_` is Box-Muller through `log`/`cos`/`sin`. Bit-for-bit was
#     *measured* on aarch64, where `NormalFill16`'s AVX2/VSX specialisations
#     do not compile and upstream runs the same scalar libm calls this shim
#     does. On a host where the vector path is live, nobody has measured
#     whether upstream's `sincos256_ps` agrees with libm -- RNG.md §6 records
#     it as unmeasured, and demanding bit equality there would be asserting
#     something no one knows. So: exact on aarch64, dtype tolerance elsewhere.
#
# The tolerance fallback is not a weaker version of the same claim; it is a
# different claim, and `_rng_stream_check` prints which one it made.

_BITWISE_NORMAL_FILL = platform.machine().lower() in ("arm64", "aarch64")


def _same_float(x, y) -> bool:
    """Exact equality, with NaN equal to NaN.

    `tolist()` widens float16/bfloat16/float32 to Python floats losslessly, so
    `==` here really is a comparison of the stored bits -- with the two
    exceptions Python's `==` has: NaN (handled) and -0.0 == 0.0 (left alone;
    neither `uniform_` nor `normal_` can produce a signed zero from a nonzero
    std or a nondegenerate range)."""
    xf, yf = float(x), float(y)
    if math.isnan(xf) or math.isnan(yf):
        return math.isnan(xf) and math.isnan(yf)
    return xf == yf


def _rng_stream_check(*, bitwise: bool, bounds=None):
    """dtype, shape, optional [lo, hi) bound, and then the draws themselves.

    `bitwise=True` demands exact agreement -- the strongest statement this
    harness can make about a random op, and the whole point of porting the
    generator. `bitwise=False` falls back to the dtype's tolerance and says so
    in its message, so a run on an unmeasured platform cannot be read as
    having proved bit equality.
    """

    def check(t_res, c_res) -> tuple[bool, str]:
        t_dtype, c_dtype = dt.dtype_name(t_res.dtype), dt.dtype_name(c_res.dtype)
        if t_dtype != c_dtype:
            return False, f"dtype mismatch: torch={t_dtype} c={c_dtype}"
        t_shape = tuple(int(x) for x in t_res.shape)
        c_shape = tuple(int(x) for x in c_res.shape)
        if t_shape != c_shape:
            return False, f"shape mismatch: torch={t_shape} c={c_shape}"
        t_flat = _flatten_values(t_res.tolist())
        c_flat = _flatten_values(c_res.tolist())
        if len(t_flat) != len(c_flat):
            return False, f"length differs: torch={len(t_flat)} c={len(c_flat)}"
        if bounds is not None:
            lo, hi = bounds
            for label, flat in (("torch", t_flat), ("c", c_flat)):
                for v in flat:
                    if not (lo <= v < hi):
                        return False, f"{label} produced {v!r}, outside requested range [{lo}, {hi})"
        if bitwise:
            for i, (x, y) in enumerate(zip(t_flat, c_flat)):
                if not _same_float(x, y):
                    return (
                        False,
                        f"stream divergence at index {i}: torch={x!r} c={y!r} "
                        "-- same seed, same generator, different value",
                    )
            return True, f"dtype={t_dtype} shape={t_shape}, {len(t_flat)} draws identical bit-for-bit"
        tol = dt.tolerance_for(t_dtype)
        ok, detail = _values_close_local(t_flat, c_flat, tol.atol, tol.rtol)
        if not ok:
            return False, detail
        return True, (
            f"dtype={t_dtype} shape={t_shape}, {len(t_flat)} draws within "
            f"atol={tol.atol}/rtol={tol.rtol} (bit equality NOT asserted: "
            f"machine={platform.machine()!r} is outside what docs/RNG.md §3.3 measured)"
        )

    return check


def _values_close_local(t_flat, c_flat, atol, rtol) -> tuple[bool, str]:
    for i, (x, y) in enumerate(zip(t_flat, c_flat)):
        xf, yf = float(x), float(y)
        if math.isnan(xf) or math.isnan(yf):
            if not (math.isnan(xf) and math.isnan(yf)):
                return False, f"index {i}: torch={x!r} c={y!r} (NaN mismatch)"
            continue
        if not math.isclose(xf, yf, rel_tol=rtol, abs_tol=atol):
            return False, f"index {i}: torch={x!r} c={y!r} (|diff|={abs(xf - yf):.6g})"
    return True, ""


def _seeded_inplace(torch_module, c_module, torch_call, op, dtype_name, shape, seed, args):
    """Both sides seeded to the same value, then the same in-place call.

    The seeding lives inside the lambdas rather than beside them because
    `compare.py` runs `run_torch` and `run_c` one after the other, and each has
    to start from the beginning of the stream rather than from wherever the
    other left it."""
    numel = 1
    for d in shape:
        numel *= d

    def run_torch():
        torch_module.manual_seed(seed)
        target = pair_from_flat(torch_module, c_module, [0.0] * numel, shape, dtype_name)[0]
        return torch_call(target, *args)

    def run_c():
        c_module._shim_manual_seed(seed)
        target = pair_from_flat(torch_module, c_module, [0.0] * numel, shape, dtype_name)[1]
        return c_module._aten_dispatch(op, target, *args)

    return run_torch, run_c


def normal__cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.normal_.default"
    cases: list[Case] = []
    # The sizes are not arbitrary. `normal_kernel` branches on
    # `size >= 16 && is_contiguous()`, and docs/RNG.md §5 item 2 names exactly
    # these five as the ones that cover both sides of it plus the tail
    # redraw: 15 is path B, 16 is path A with no tail, 17 and 20 are path A
    # *rewriting sixteen elements it already computed*, and 32 is path A with
    # the tail case skipped again. From one seed, n=15 and n=16 share not a
    # single value; n=17 differs from n=16 in its first element too. A shim
    # that reproduced the stream and missed the blocking would pass a
    # distribution test and fail every one of these.
    sizes = [
        (6, "path B (size < 16), the size this case used before the port"),
        (15, "path B, one below the boundary"),
        (16, "path A, exactly one block, no tail redraw"),
        (17, "path A + tail: the last 16 elements are drawn again over the top"),
        (20, "path A + tail, mid-block"),
        (32, "path A, two whole blocks, no tail"),
    ]
    for dtype_name in _MUL_DIV_FLOAT_DTYPES:
        for mean, std, why in [
            (0.0, 1.0, "standard normal -- typical init"),
            (0.0, 0.02, "small std, transformer-init style"),
        ]:
            for n, path in sizes:
                for seed in (0, 42):
                    run_torch, run_c = _seeded_inplace(
                        torch_module, c_module, torch_call, op, dtype_name, (n,), seed, (mean, std)
                    )
                    cases.append(
                        Case(
                            name=(
                                f"normal_(dtype={dtype_name}, n={n}, mean={mean}, std={std}, "
                                f"seed={seed}) [{path}]"
                            ),
                            op=op,
                            run_torch=run_torch,
                            run_c=run_c,
                            value_check=_rng_stream_check(bitwise=_BITWISE_NORMAL_FILL),
                            note=why + " -- " + path,
                        )
                    )
    cases.append(
        Case(
            name="normal_(float32, std < 0 rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(
                pair_from_flat(torch_module, c_module, [0.0] * 4, (4,), "float32")[0], 0.0, -1.0
            ),
            run_c=lambda: c_module._aten_dispatch(
                op, pair_from_flat(torch_module, c_module, [0.0] * 4, (4,), "float32")[1], 0.0, -1.0
            ),
            expect="both_error",
            note="torch: 'normal expects std >= 0.0, but found std -1'",
        )
    )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # self/mean/std all by keyword, seeded the same way `_seeded_inplace`
    # seeds every other case above.
    def _kw_normal_run_torch():
        torch_module.manual_seed(0)
        target = pair_from_flat(torch_module, c_module, [0.0] * 6, (6,), "float32")[0]
        return torch_call(self=target, mean=0.0, std=1.0)

    def _kw_normal_run_c():
        c_module._shim_manual_seed(0)
        target = pair_from_flat(torch_module, c_module, [0.0] * 6, (6,), "float32")[1]
        return c_module._aten_dispatch(op, self=target, mean=0.0, std=1.0)

    cases.append(
        Case(
            name="normal_(self=/mean=/std= all by keyword)",
            op=op,
            run_torch=_kw_normal_run_torch,
            run_c=_kw_normal_run_c,
            value_check=_rng_stream_check(bitwise=_BITWISE_NORMAL_FILL),
        )
    )
    return cases


def uniform__cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.uniform_.default"
    cases: list[Case] = []
    # `(2.0, 7.5)` is here for a specific reason: every range anyone tries
    # first -- (0,1), (-1,1), (-0.5,0.5) -- has a power-of-two width, which
    # makes the affine step's multiply exact and hides whether it was written
    # as `x*(to-from)+from` or as the fused multiply-add clang actually
    # compiles. rng.rs' comment records ~9.5% of draws coming out 1 ulp low
    # before that was `mul_add`. Only a non-power-of-two width can see it, and
    # only a bit-exact comparison can report it.
    ranges = [
        (0.0, 1.0, "default range"),
        (-1.0, 1.0, "range straddling zero"),
        (2.0, 7.5, "non-power-of-two width -- the only range that sees the fused multiply-add"),
    ]
    for dtype_name in _MUL_DIV_FLOAT_DTYPES:
        for lo, hi, why in ranges:
            for n in (6, 17, 1000):
                for seed in (0, 42):
                    run_torch, run_c = _seeded_inplace(
                        torch_module, c_module, torch_call, op, dtype_name, (n,), seed, (lo, hi)
                    )
                    cases.append(
                        Case(
                            name=f"uniform_(dtype={dtype_name}, n={n}, from={lo}, to={hi}, seed={seed}) [{why}]",
                            op=op,
                            run_torch=run_torch,
                            run_c=run_c,
                            # The bound is kept alongside the exact comparison,
                            # not replaced by it: the half-open guarantee is
                            # enforced by a clamp applied *after* the narrowing
                            # cast, and on float16 with to=1.0 that clamp fires
                            # about one draw in 4096. A shim missing it agrees
                            # with the stream everywhere else.
                            value_check=_rng_stream_check(bitwise=True, bounds=(lo, hi)),
                            note=why + " -- bit-for-bit; docs/RNG.md §5 item 3 allows this on every platform",
                        )
                    )
    cases.append(
        Case(
            name="uniform_(float32, from > to rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(
                pair_from_flat(torch_module, c_module, [0.0] * 4, (4,), "float32")[0], 1.0, 0.0
            ),
            run_c=lambda: c_module._aten_dispatch(
                op, pair_from_flat(torch_module, c_module, [0.0] * 4, (4,), "float32")[1], 1.0, 0.0
            ),
            expect="both_error",
            note="torch: 'uniform_ expects to return a [from, to) range, but found from=1 > to=0'",
        )
    )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # self/from/to all by keyword. `from` is a Python keyword, so it can only
    # be spelled through `**{"from": ...}`, not `from=...` at the call site --
    # which is itself a real shape `dispatch(key, **bound)` can produce.
    def _kw_uniform_run_torch():
        torch_module.manual_seed(0)
        target = pair_from_flat(torch_module, c_module, [0.0] * 6, (6,), "float32")[0]
        return torch_call(**{"self": target, "from": 2.0, "to": 7.5})

    def _kw_uniform_run_c():
        c_module._shim_manual_seed(0)
        target = pair_from_flat(torch_module, c_module, [0.0] * 6, (6,), "float32")[1]
        return c_module._aten_dispatch(op, **{"self": target, "from": 2.0, "to": 7.5})

    cases.append(
        Case(
            name="uniform_(self=/from=/to= all by keyword)",
            op=op,
            run_torch=_kw_uniform_run_torch,
            run_c=_kw_uniform_run_c,
            value_check=_rng_stream_check(bitwise=True, bounds=(2.0, 7.5)),
        )
    )
    return cases


# --- aten.bernoulli_.float, and the dropout composite over it (docs/TRAIN.md) --
#
# The whole of training mode rests on this one kernel. `nn.Dropout` decomposes
# onto it (`empty_like`, `bernoulli_.float`, `div_.Scalar`, `mul.Tensor`) and
# DeBERTa's `XDropout` calls it directly, so both spellings are here: the
# dispatch key, and the `torch.dropout` composite that golden is structurally
# blind to because it has no key of its own.
#
# THE QUESTION TO ASK OF A STOCHASTIC KERNEL is which wrong implementations
# still pass. Four are cheap to write and all four are covered below:
#
#   * one that draws 32-bit words instead of 64-bit (i.e. copies `uniform_`'s
#     `opmath_type<scalar_t>` rule). Right distribution, wrong stream --
#     invisible to any statistical check, caught by the seeded bit comparison.
#   * one that short-circuits `p == 0` / `p == 1` without drawing. Right
#     values, wrong generator state -- invisible to any check that looks only
#     at the returned tensor, caught by `[after]` below, which draws again and
#     compares *that*.
#   * one that answers `zeros_like` for `dropout(p=1)`. Right on every finite
#     input, wrong on `-0.0` and on `±inf` -- caught by `_signed_zero_check`
#     over a vector that contains both.
#   * one that scales the *input* by `1/(1-p)` instead of scaling the mask in
#     the mask's dtype. Identical in float32, off by ~0.005 in bfloat16 --
#     caught by the bfloat16 survivor-value cases.

_BERNOULLI_DTYPES = [
    "float64", "float32", "float16", "bfloat16",
    "int64", "int32", "int16", "uint8", "bool",
]


def _seeded_bernoulli(torch_module, c_module, torch_call, dtype_name, n, p, seed):
    """Both sides seeded alike, then `bernoulli_(p)` over an `n`-element zero
    tensor. Built with an integer fill rather than `0.0` so the same call
    works for `bool` and the integral dtypes, which `bernoulli_` accepts and
    `uniform_` does not."""

    def run_torch():
        torch_module.manual_seed(seed)
        target = pair_from_flat(torch_module, c_module, [0] * n, (n,), dtype_name)[0]
        return torch_call(target, p)

    def run_c():
        c_module._shim_manual_seed(seed)
        target = pair_from_flat(torch_module, c_module, [0] * n, (n,), dtype_name)[1]
        return c_module._aten_dispatch("aten.bernoulli_.float", target, p)

    return run_torch, run_c


def _seeded_stream_after(torch_module, c_module, before_torch, before_c, n=6):
    """Run something, then draw `n` float64 uniforms and return **those**.

    This is the only case shape that can see a kernel which produced the right
    tensor from the wrong number of draws. `bernoulli_` consumes `numel`
    64-bit words for every `p`, `p == 0` and `p == 1` included (measured,
    docs/TRAIN.md §2); a shim that skipped the draw would return an identical
    tensor and desynchronise everything after it.
    """

    def run_torch():
        torch_module.manual_seed(7)
        before_torch()
        after = torch_module.empty(n, dtype=torch_module.float64)
        return after.uniform_(0.0, 1.0)

    def run_c():
        c_module._shim_manual_seed(7)
        before_c()
        after = c_module._tensor_from_flat([0.0] * n, [n], dtype=c_module.float64)
        return c_module._aten_dispatch("aten.uniform_.default", after, 0.0, 1.0)

    return run_torch, run_c


def bernoulli__float_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.bernoulli_.float"
    cases: list[Case] = []

    # 1. The stream itself, bit for bit, across every dtype upstream accepts.
    #    The dtype sweep is the point: `bernoulli_` draws in `double` for ALL
    #    of them, unlike `uniform_`, so a shim that reused `uniform_`'s
    #    accumulate-type rule agrees on float64 and diverges on the other
    #    eight. Only comparing more than one dtype can see that.
    for dtype_name in _BERNOULLI_DTYPES:
        for p in (0.25, 0.5, 0.9):
            for n in (6, 17):
                for seed in (0, 42):
                    run_torch, run_c = _seeded_bernoulli(
                        torch_module, c_module, torch_call, dtype_name, n, p, seed
                    )
                    cases.append(
                        Case(
                            name=f"bernoulli_(dtype={dtype_name}, n={n}, p={p}, seed={seed})",
                            op=op,
                            run_torch=run_torch,
                            run_c=run_c,
                            value_check=_rng_stream_check(bitwise=True),
                            note="upstream's bernoulli_distribution<double> takes "
                                 "generator->random64() for every scalar_t -- bit-for-bit",
                        )
                    )

    # A large draw, so the *fraction* is a real statement and not noise. It is
    # kept alongside the bit comparison rather than instead of it: this is the
    # check a reader believes on sight, and it is also the one a completely
    # wrong stream would still pass.
    for p in (0.1, 0.5, 0.9):
        run_torch, run_c = _seeded_bernoulli(
            torch_module, c_module, torch_call, "float32", 4000, p, 0
        )
        cases.append(
            Case(
                name=f"bernoulli_(float32, n=4000, p={p}) [survivor fraction ~= p]",
                op=op,
                run_torch=run_torch,
                run_c=run_c,
                value_check=_rng_stream_check(bitwise=True),
                note="4000 draws: the mean is p to within ~1.6% at 2 sigma, and the "
                     "bit comparison says the two sides agree draw for draw",
            )
        )

    # 2. The degenerate probabilities, which are exact and have no randomness.
    for p, expect_note in ((0.0, "all zeros -- a draw is never negative"),
                           (1.0, "all ones -- the range is half-open, a draw is never 1.0")):
        for dtype_name in ("float32", "int64", "bool"):
            run_torch, run_c = _seeded_bernoulli(
                torch_module, c_module, torch_call, dtype_name, 8, p, 3
            )
            cases.append(
                Case(
                    name=f"bernoulli_(dtype={dtype_name}, p={p}) [{expect_note}]",
                    op=op,
                    run_torch=run_torch,
                    run_c=run_c,
                    value_check=_rng_stream_check(bitwise=True),
                    note=expect_note,
                )
            )

    # 3. ...and that they still consume the stream. This is the case that
    #    fails against the obvious short-circuit and nothing else does.
    for p in (0.0, 1.0, 0.5):
        def before_torch(p=p):
            torch_module.empty(9, dtype=torch_module.float32).bernoulli_(p)

        def before_c(p=p):
            target = c_module._tensor_from_flat([0.0] * 9, [9], dtype=c_module.float32)
            c_module._aten_dispatch(op, target, p)

        run_torch, run_c = _seeded_stream_after(
            torch_module, c_module, before_torch, before_c
        )
        cases.append(
            Case(
                name=f"bernoulli_(p={p}) then uniform_ [the draws AFTER it]",
                op=op,
                run_torch=run_torch,
                run_c=run_c,
                value_check=_rng_stream_check(bitwise=True, bounds=(0.0, 1.0)),
                note="the result is the following uniform_ fill, not the bernoulli_ "
                     "itself: a p==0 or p==1 short-circuit returns the right tensor "
                     "and leaves the generator 9 draws behind",
            )
        )

    # 4. Refusals, both sides.
    for p in (-0.1, 1.5, float("nan")):
        t_t, t_c = pair_from_flat(torch_module, c_module, [0, 0, 0, 0], (4,), "float32")
        cases.append(
            Case(
                name=f"bernoulli_(p={p!r}) [refused on both sides]",
                op=op,
                run_torch=lambda t_t=t_t, p=p: torch_call(t_t, p),
                run_c=lambda t_c=t_c, p=p: c_module._aten_dispatch(op, t_c, p),
                expect="both_error",
                note="torch: 'bernoulli_ expects p to be in [0, 1], but got p=...'. "
                     "nan is refused because the check is `0 <= p && p <= 1`, which "
                     "nan fails on both halves -- `p < 0 || p > 1` would let it through",
            )
        )
    u_t, u_c = pair_from_flat(torch_module, c_module, [0, 1, 2], (3,), "uint32")
    cases.append(
        Case(
            name="bernoulli_(dtype=uint32) [refused on both sides]",
            op=op,
            run_torch=lambda: torch_call(u_t, 0.5),
            run_c=lambda: c_module._aten_dispatch(op, u_c, 0.5),
            expect="both_error",
            note="AT_DISPATCH_ALL_TYPES_AND3(Bool, BFloat16, Half) does not cover "
                 "uint32; upstream: '\"bernoulli_scalar_cpu_\" not implemented for "
                 "'UInt32''. candle can store it, which is exactly why this has to "
                 "be refused deliberately rather than served by accident",
        )
    )

    # 5. Empty tensor: no draws, no error, shape preserved.
    run_torch, run_c = _seeded_bernoulli(torch_module, c_module, torch_call, "float32", 0, 0.5, 1)
    cases.append(
        Case(
            name="bernoulli_(float32, numel=0)",
            op=op,
            run_torch=run_torch,
            run_c=run_c,
            value_check=_rng_stream_check(bitwise=True),
            note="an empty fill draws nothing and returns an empty tensor",
        )
    )

    # 6. The member spelling. `methods.json` is what makes `x.bernoulli_(p)`
    #    resolve, and golden compares by dispatch key -- so deleting that entry
    #    fails here and nowhere else. `sew_d` uses exactly this spelling.
    def _member_bernoulli(seed, p, dtype_name, n):
        def run_torch():
            torch_module.manual_seed(seed)
            t = pair_from_flat(torch_module, c_module, [0] * n, (n,), dtype_name)[0]
            t.bernoulli_(p)
            return t

        def run_c():
            c_module._shim_manual_seed(seed)
            t = pair_from_flat(torch_module, c_module, [0] * n, (n,), dtype_name)[1]
            t.bernoulli_(p)
            return t

        return run_torch, run_c

    for dtype_name in ("float32", "bool"):
        run_torch, run_c = _member_bernoulli(11, 0.6, dtype_name, 12)
        cases.append(
            Case(
                name=f"spelling x.bernoulli_(0.6) (dtype={dtype_name})",
                op=op,
                run_torch=run_torch,
                run_c=run_c,
                value_check=_rng_stream_check(bitwise=True),
                note="sew_d: (1 - torch.empty_like(x).bernoulli_(1 - p)).to(torch.bool)",
            )
        )

    # `p` by keyword, the other half of the binding (docs/DISPATCH.md §4.1).
    def _kw_run_torch():
        torch_module.manual_seed(0)
        t = pair_from_flat(torch_module, c_module, [0] * 6, (6,), "float32")[0]
        return torch_call(self=t, p=0.75)

    def _kw_run_c():
        c_module._shim_manual_seed(0)
        t = pair_from_flat(torch_module, c_module, [0] * 6, (6,), "float32")[1]
        return c_module._aten_dispatch(op, self=t, p=0.75)

    cases.append(
        Case(
            name="bernoulli_(self=/p= by keyword)",
            op=op,
            run_torch=_kw_run_torch,
            run_c=_kw_run_c,
            value_check=_rng_stream_check(bitwise=True),
        )
    )

    # 7. The composite. It has no dispatch key of its own -- `aten::dropout` is
    #    CompositeImplicitAutograd and never reaches the dispatcher (measured,
    #    docs/TRAIN.md §1) -- so it is compared here, through the two Python
    #    spellings that exist, against upstream's `torch.dropout`.
    cases.extend(_dropout_composite_cases(torch_module, c_module, op))
    return cases


_DROPOUT_DTYPES = ["float64", "float32", "float16", "bfloat16"]


def _dropout_composite_cases(torch_module, c_module, op) -> list[Case]:
    """`torch.dropout` / `torch.dropout_`, seeded, against upstream's."""
    cases: list[Case] = []

    def seeded(spelling, dtype_name, flat, shape, p, train, seed, check, note):
        def side(module, which):
            def run():
                if which == "torch":
                    module.manual_seed(seed)
                else:
                    module._shim_manual_seed(seed)
                t = pair_from_flat(torch_module, c_module, flat, shape, dtype_name)[
                    0 if which == "torch" else 1
                ]
                return _free(module, spelling)(t, p, train)

            return run

        return Case(
            name=f"{spelling}(dtype={dtype_name}, p={p}, train={train}, seed={seed})",
            op=op,
            run_torch=side(torch_module, "torch"),
            run_c=side(c_module, "c"),
            value_check=check,
            note=note,
        )

    # The random path, bit for bit, in every float dtype.
    #
    # **THE INPUT IS NOT ONES, AND THAT IS THE WHOLE POINT.** The first draft
    # of these cases used `[1.0] * 24`, and a deliberate sabotage -- replacing
    # `noise.div_(1-p); input * noise` with `(input * (1/(1-p))) * noise`, the
    # single most plausible wrong shape for this composite -- passed every one
    # of them, and passed the smoke tests and the training sweep too. On an
    # all-ones input the two are identical by construction: both end up
    # multiplying by the same rounded `1/(1-p)`. Measured on upstream over
    # 4000 random values, they differ on ~10% of the survivors by one ULP in
    # `float16` and `bfloat16`, and not at all in `float32`. So the values
    # below span a real range and there are enough of them that the 10% is a
    # certainty rather than a coin flip.
    spread = [round(v * 3.0, 4) for v in _deterministic(240, 9)]
    for dtype_name in _DROPOUT_DTYPES:
        for p in (0.25, 0.7):
            for spelling in ("dropout", "dropout_"):
                cases.append(
                    seeded(
                        spelling, dtype_name, spread, (10, 24), p, True, 5,
                        _bitwise_equal_check,
                        "survivors are input x (1/(1-p) rounded in the MASK's "
                        "dtype). A shim that scaled the INPUT by a Python "
                        "1/(1-p) instead agrees in float32 and differs by 1 ULP "
                        "on ~10% of the survivors in float16/bfloat16 -- "
                        "measured, and it passes an all-ones input, which is "
                        "what this case used to be",
                    )
                )

    # The exact paths: no randomness at all, so these are the strongest
    # statements here and they are also most of the real call sites.
    for dtype_name in _DROPOUT_DTYPES:
        for p, train, why in (
            (0.0, True, "p == 0 in train mode is the identity"),
            (0.5, False, "eval mode is the identity for any p"),
            (0.0, False, "both short-circuits at once"),
        ):
            cases.append(
                seeded(
                    "dropout", dtype_name, [1.5, -2.5, 0.0, -0.0, 7.25, -1.0], (6,),
                    p, train, 1, _signed_zero_check, why + " -- bit for bit, signed zero included",
                )
            )

    # p == 1: `input * zeros({})`, and the three inputs that tell it apart from
    # `zeros_like`. Any of `-0.0`, `inf`, `-inf` alone would do it; all three
    # are here because a reader should not have to know which one is load
    # bearing.
    special = [1.0, -1.0, 0.0, -0.0, float("inf"), float("-inf")]
    for spelling in ("dropout", "dropout_"):
        cases.append(
            seeded(
                spelling, "float32", special, (6,), 1.0, True, 1, _signed_zero_check,
                "p == 1 is a multiply by zero: -0.0 stays -0.0 and +-inf becomes nan. "
                "zeros_like passes (y == 0).all() and fails this",
            )
        )
        cases.append(
            seeded(
                spelling, "float64", special, (6,), 1.0, True, 1, _signed_zero_check,
                "same, in float64",
            )
        )

    # The identity return is the identity OBJECT upstream, not a copy.
    for p, train in ((0.0, True), (0.5, False)):
        def ident(module, which, p=p, train=train):
            def run():
                t = pair_from_flat(
                    torch_module, c_module, [1.0, 2.0], (2,), "float32"
                )[0 if which == "torch" else 1]
                return _free(module, "dropout")(t, p, train) is t

            return run

        cases.append(
            Case(
                name=f"dropout(p={p}, train={train}) returns the SAME object",
                op=op,
                run_torch=ident(torch_module, "torch"),
                run_c=ident(c_module, "c"),
                value_check=_scalar_match_check,
                note="upstream's `return input;` is the identity, not a clone -- "
                     "measured; a `clone()` here would pass every value comparison",
            )
        )

    # numel == 0 short-circuits before anything is drawn.
    cases.append(
        seeded("dropout", "float32", [], (0,), 0.5, True, 1, _bitwise_equal_check,
               "an empty input short-circuits: upstream draws nothing")
    )

    # The range check runs BEFORE the short-circuit, so an eval-mode call with
    # a nonsense p still raises. The shim used to return `input` here.
    for p, train in ((1.5, False), (-0.1, False), (float("nan"), True), (1.5, True)):
        t_t, t_c = pair_from_flat(torch_module, c_module, [1.0, 2.0], (2,), "float32")
        cases.append(
            Case(
                name=f"dropout(p={p!r}, train={train}) [refused on both sides]",
                op=op,
                run_torch=lambda t_t=t_t, p=p, train=train: _free(torch_module, "dropout")(t_t, p, train),
                run_c=lambda t_c=t_c, p=p, train=train: _free(c_module, "dropout")(t_c, p, train),
                expect="both_error",
                note="torch: 'dropout probability has to be between 0 and 1, but got ...' "
                     "-- TORCH_CHECK precedes `if (p == 0 || !train || numel == 0)`, so "
                     "train=False does NOT excuse an out-of-range p",
            )
        )

    # And that the composite leaves the generator where upstream leaves it:
    # four draws' worth for a 4-element input, not zero and not eight.
    for p, train in ((0.5, True), (0.0, True), (1.0, True), (0.5, False)):
        def before_torch(p=p, train=train):
            _free(torch_module, "dropout")(torch_module.ones(4), p, train)

        def before_c(p=p, train=train):
            t = c_module._tensor_from_flat([1.0] * 4, [4], dtype=c_module.float32)
            _free(c_module, "dropout")(t, p, train)

        run_torch, run_c = _seeded_stream_after(
            torch_module, c_module, before_torch, before_c
        )
        cases.append(
            Case(
                name=f"dropout(p={p}, train={train}) then uniform_ [the draws AFTER it]",
                op=op,
                run_torch=run_torch,
                run_c=run_c,
                value_check=_rng_stream_check(bitwise=True, bounds=(0.0, 1.0)),
                note="p==0, p==1 and train=False each draw a DIFFERENT amount "
                     "(0, 4 and 0 respectively); this is the only case that sees it",
            )
        )
    return cases


def div__scalar_cases(torch_module, c_module, torch_call) -> list[Case]:
    """`aten::div_.Scalar` -- `noise.div_(1 - p)`, dropout's scale step.

    The hole in the middle of a family that was otherwise complete:
    `div.Scalar` out of place, and `add_`/`sub_`/`mul_` `.Scalar` in place,
    were all already here. What makes this one not a copy of `mul_.Scalar` is
    the promotion: true division always produces a float, so an integral
    receiver refuses rather than flooring."""
    op = "aten.div_.Scalar"
    cases: list[Case] = []

    for dtype_name in ["float64", "float32", "float16", "bfloat16"]:
        for scalar in (2.0, 0.3, -4.0):
            dst_t, dst_c = pair_from_flat(
                torch_module, c_module, [1.0, 2.0, 3.0, 4.0], (2, 2), dtype_name
            )
            cases.append(
                Case(
                    name=f"div_(dtype={dtype_name}, other={scalar!r})",
                    op=op,
                    run_torch=lambda dst_t=dst_t, s=scalar: torch_call(dst_t, s),
                    run_c=lambda dst_c=dst_c, s=scalar: c_module._aten_dispatch(op, dst_c, s),
                    value_check=_bitwise_equal_check,
                    note="0.3 is not representable in any of these dtypes, so the "
                         "quotient depends on where the narrowing happens -- compared "
                         "bit for bit because the dtype tolerance would absorb it",
                )
            )

    # dropout's exact call: a 0/1 mask divided by the keep probability. The
    # survivor value IS the thing dropout multiplies by.
    for dtype_name in ["float32", "bfloat16", "float16"]:
        dst_t, dst_c = pair_from_flat(
            torch_module, c_module, [1.0, 0.0, 1.0, 1.0], (4,), dtype_name
        )
        cases.append(
            Case(
                name=f"div_(dtype={dtype_name}, mask / 0.3) [dropout's scale step]",
                op=op,
                run_torch=lambda dst_t=dst_t: torch_call(dst_t, 0.3),
                run_c=lambda dst_c=dst_c: c_module._aten_dispatch(op, dst_c, 0.3),
                value_check=_bitwise_equal_check,
                note="bfloat16 answers 3.328125 and float16 answers 3.333984375; "
                     "a shim that computed 1/(1-p) in float and multiplied would "
                     "give 3.3333333 in both",
            )
        )

    zero_t, zero_c = pair_from_flat(
        torch_module, c_module, [1.0, -1.0, 0.0, float("nan")], (4,), "float32"
    )
    cases.append(
        Case(
            name="div_(float32, by 0.0) [inf/-inf/nan, not an error]",
            op=op,
            run_torch=lambda: torch_call(zero_t, 0.0),
            run_c=lambda: c_module._aten_dispatch(op, zero_c, 0.0),
            value_check=_signed_zero_check,
            note="IEEE division, and 0.0/0.0 is nan -- the same answers div.Scalar gives",
        )
    )

    for dtype_name, scalar in (("int64", 2), ("int32", 2), ("uint8", 2)):
        e_t, e_c = pair_from_flat(torch_module, c_module, [1, 2, 3], (3,), dtype_name)
        cases.append(
            Case(
                name=f"div_(dtype={dtype_name}, other={scalar}) [refused on both sides]",
                op=op,
                run_torch=lambda e_t=e_t, s=scalar: torch_call(e_t, s),
                run_c=lambda e_c=e_c, s=scalar: c_module._aten_dispatch(op, e_c, s),
                expect="both_error",
                note="true division promotes to float and cannot be written back into "
                     "an integral receiver -- this is what separates div_ from mul_, "
                     "which accepts an int scalar happily",
            )
        )

    cases.extend(_inplace_member_cases(torch_module, c_module, op, [
        ("x.div_(2.0)", lambda m, a: a.div_(2.0)),
        # `x /= 2.0` is deliberately NOT here, and the reason is measured
        # rather than assumed: `_C.TensorBase` has `__idiv__` and no
        # `__itruediv__`, so on the bare shim module `x /= 2.0` falls back to
        # `x = x / 2.0` and rebinds a local, leaving the base untouched --
        # while `torch.Tensor` (which `torch/_tensor.py:1115` patches) writes
        # through. That is a difference between the two *modules*, not between
        # the two kernels, and a case comparing them would have failed for a
        # reason having nothing to do with `div_.Scalar`.
        ("x.__idiv__(2.0)", lambda m, a: a.__idiv__(2.0)),
    ], operands=1))
    cases.extend(c for c in _view_write_cases(torch_module, c_module) if c.op == op)
    return cases


# --- the eight ops a greedy 2-layer Llama forward stopped on (docs/GAP.md §3) --
#
# These are not "more coverage". Before them `_aten_dispatch` refused eight
# names the forward pass reaches, so the model could not run at all; docs/OPS8.md
# records the run that follows from landing them.
#
# Two of the eight are not shaped like anything else in this file and get their
# own treatment below:
#
#   * `bmm` is the batched matmul, and it inherits `mm`'s dtype gap exactly --
#     candle has no matmul kernel for the integer dtypes or bfloat16, so the
#     same split into match / c_error / both_error that `mm_cases` uses applies
#     here verbatim. It also has three *refusals* worth pinning: 2-D input,
#     mismatched dtypes, and -- the one that matters -- a batch of 1 against a
#     batch of 2. `matmul` broadcasts that; `bmm` must not, and a case is the
#     only thing that keeps a later "simplification" from routing one at the
#     other.
#   * `_scaled_dot_product_flash_attention_for_cpu` answers with a *pair*
#     (output, logsumexp) and the two halves do not even share a dtype: for a
#     `float16` input the output is `float16` and the logsumexp is `float32`.
#     `_sdpa_pair_check` below compares both halves including that asymmetry,
#     because it is the observable evidence that the accumulation happens in
#     float, and a shim that returned `float16` there would be wrong in a way
#     no value comparison would catch.


def _deterministic(n: int, seed: int = 1) -> list[float]:
    """`n` reproducible values in roughly [-1, 1].

    Not `random` and not `torch.randn`: both sides of every case have to be
    fed *the same* numbers, and the only way to guarantee that across two
    tensor libraries is to compute them in plain Python and hand the same
    list to each. Values stay near unit magnitude so that `bfloat16`'s
    tolerance (6e-2, dtypes.py) is still a real check rather than a rubber
    stamp.
    """
    out, state = [], seed
    for _ in range(n):
        state = (state * 1103515245 + 12345) % 2147483648
        out.append(round((state / 2147483648.0) * 2.0 - 1.0, 4))
    return out


def bmm_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.bmm.default"
    cases: list[Case] = []

    # (2, 3, 4) @ (2, 4, 5) -- attention's shape, and a batch big enough that
    # a kernel that quietly dropped the batch dimension would show up.
    a_flat, a_shape = list(range(24)), (2, 3, 4)
    b_flat, b_shape = list(range(40)), (2, 4, 5)
    # (1, 2, 2) @ (1, 2, 2) -- a batch of one, where the answer is `mm`'s and
    # can be checked by hand: [[1,2],[3,4]] @ [[5,6],[7,8]] == [[19,22],[43,50]].
    unit_a, unit_b = [1.0, 2.0, 3.0, 4.0], [5.0, 6.0, 7.0, 8.0]

    for dtype_name in _MM_MATCH_DTYPES:
        for af, ash, bf, bsh, note in [
            (a_flat, a_shape, b_flat, b_shape, "batched (2,3,4)x(2,4,5) -- attention's QK^T shape"),
            (unit_a, (1, 2, 2), unit_b, (1, 2, 2), "batch of one, hand-checkable 2x2"),
        ]:
            at, ac = pair_from_flat(torch_module, c_module, af, ash, dtype_name)
            bt, bc = pair_from_flat(torch_module, c_module, bf, bsh, dtype_name)
            cases.append(
                Case(
                    name=f"bmm(dtype={dtype_name}, {ash}x{bsh}) [{note}]",
                    op=op,
                    run_torch=lambda at=at, bt=bt: torch_call(at, bt),
                    run_c=lambda ac=ac, bc=bc: c_module._aten_dispatch(op, ac, bc),
                    note=note,
                )
            )

    # The same candle gap `mm_cases` records, re-checked through `bmm`: if it
    # ever closes for one op it should close for both, and these cases say so.
    for dtype_name in _MM_C_ERROR_DTYPES:
        at, ac = pair_from_flat(torch_module, c_module, a_flat, a_shape, dtype_name)
        bt, bc = pair_from_flat(torch_module, c_module, b_flat, b_shape, dtype_name)
        cases.append(
            Case(
                name=f"bmm(dtype={dtype_name}, batched)",
                op=op,
                run_torch=lambda at=at, bt=bt: torch_call(at, bt),
                run_c=lambda ac=ac, bc=bc: c_module._aten_dispatch(op, ac, bc),
                expect="c_error",
                note=(
                    f"candle's matmul has no kernel for {dtype_name}; torch's CPU baddbmm "
                    "does. Same gap mm_cases records for mm -- tracked separately so "
                    "closing it for one op cannot silently look like closing it for both."
                ),
            )
        )

    at, ac = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (1, 2, 2), "uint32")
    cases.append(
        Case(
            name="bmm(dtype=uint32, batched)",
            op=op,
            run_torch=lambda: torch_call(at, at),
            run_c=lambda: c_module._aten_dispatch(op, ac, ac),
            expect="both_error",
            note="neither torch nor candle has a uint32 matmul; neither should invent one.",
        )
    )

    # The three refusals. The batch-broadcast one is the load-bearing case:
    # `matmul.default`'s kernel (candle's `broadcast_matmul`) computes here,
    # and `bmm` must not.
    two_t, two_c = pair_from_flat(torch_module, c_module, [1.0] * 12, (3, 4), "float32")
    three_t, three_c = pair_from_flat(torch_module, c_module, [1.0] * 20, (4, 5), "float32")
    cases.append(
        Case(
            name="bmm(2D input rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(two_t, three_t),
            run_c=lambda: c_module._aten_dispatch(op, two_c, three_c),
            expect="both_error",
            note="torch: 'batch1 must be a 3D tensor'. bmm must not stand in for mm.",
        )
    )

    one_t, one_c = pair_from_flat(torch_module, c_module, [1.0] * 12, (1, 3, 4), "float32")
    many_t, many_c = pair_from_flat(torch_module, c_module, [1.0] * 40, (2, 4, 5), "float32")
    cases.append(
        Case(
            name="bmm(batch 1 x batch 2 rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(one_t, many_t),
            run_c=lambda: c_module._aten_dispatch(op, one_c, many_c),
            expect="both_error",
            note=(
                "bmm does not broadcast its batch dimension -- torch: 'Expected size for "
                "first two dimensions of batch2 tensor to be: [1, 4] but got: [2, 4].' "
                "This is exactly the case a one-line route into matmul_default would get "
                "wrong, because candle's broadcast_matmul computes it."
            ),
        )
    )

    f32_t, f32_c = pair_from_flat(torch_module, c_module, [1.0] * 24, (2, 3, 4), "float32")
    f64_t, f64_c = pair_from_flat(torch_module, c_module, [1.0] * 40, (2, 4, 5), "float64")
    cases.append(
        Case(
            name="bmm(float32 x float64 rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(f32_t, f64_t),
            run_c=lambda: c_module._aten_dispatch(op, f32_c, f64_c),
            expect="both_error",
            note="torch: 'expected scalar type Float but found Double'; _C: same_dtype refuses.",
        )
    )

    # Model-scale, batched. Attention's QK^T is a bmm of depth head_dim and
    # its AV is a bmm of depth seq_len, so this is where a large k actually
    # shows up in a transformer -- see the note above `_gemm_scale_check`.
    for dtype_name, note in [
        ("float32", "batched depth 512 -- attention's AV at seq_len 512"),
        ("float16", "the same, in the dtype a device would actually run"),
    ]:
        cases.append(
            _big_gemm_case(torch_module, c_module, torch_call, "aten.bmm.default",
                           dtype_name, 8, 512, 8, batch=2, note=note)
        )
    cases.extend(_einsum_cases(torch_module, c_module))
    return cases


def _einsum_cases(torch_module, c_module) -> list[Case]:
    """`torch.einsum` -- `sam3_video`'s wall after `div`'s promotion.

    Cased under `aten.bmm.default` because that is the op it fires: `aten::einsum`
    is `CompositeImplicitAutograd`, and a `TorchDispatchMode` trace of
    `einsum("bqc,bkc->bqk", ...)` reports `unsqueeze`, `permute`, `view`,
    **`bmm`**, `view`, `permute`, `view` -- no `aten.einsum.default` at all. So
    golden has no dispatch key for it and only spelling cases can see it.

    Each equation below is a different shape of the algorithm, and the set is
    chosen so that a decomposition which handles the common case and nothing
    else fails somewhere:

        bqc,bchw->bqhw   sam3_video's own call: free axes on BOTH sides, and
                         two of them on the right, so the reshape to (B,K,N)
                         has to fold a pair
        bqc,bkc->bqk     the attention shape: one free axis each
        ij,jk->ik        no batch axis at all -- B is the empty product, 1
        ij,jk            IMPLICIT output: every label appearing once, in
                         ALPHABETICAL order. `ik`, not `ki`
        i,i->            everything contracted: the result is 0-d, and both
                         M and N are empty products
        ij->ji           one operand, no contraction: a pure permute
        ij->             one operand, everything summed
        ij,j->i          a rank-1 right operand
        abc,abd->acd     a label in BOTH inputs and NOT in the output (`b`),
                         beside a batch label that is (`a`) -- the case that
                         separates "batch" from "summed"
        ijk->ik          a label summed out of a single operand
    """
    op = "aten.bmm.default"
    cases: list[Case] = []

    def operand(shape, salt):
        n = 1
        for extent in shape:
            n *= extent
        flat = [float(((i + salt) * 7) % 13) - 6.0 for i in range(n)]
        return pair_from_flat(torch_module, c_module, flat, shape, "float32")

    for equation, shapes, note in (
        ("bqc,bchw->bqhw", [(1, 5, 4), (1, 4, 3, 3)], "sam3_video's own call"),
        ("bqc,bkc->bqk", [(2, 3, 4), (2, 5, 4)], "the attention shape"),
        ("ij,jk->ik", [(2, 3), (3, 4)], "a plain matmul, no batch axis"),
        ("ij,jk", [(2, 3), (3, 4)], "IMPLICIT output: alphabetical, so ik"),
        ("i,i->", [(5,), (5,)], "a dot product; the result is 0-d"),
        ("ij->ji", [(2, 3)], "one operand: a pure permute"),
        ("ij->", [(2, 3)], "one operand: everything summed"),
        ("ij,j->i", [(2, 3), (3,)], "a rank-1 right operand"),
        ("abc,abd->acd", [(2, 3, 4), (2, 3, 5)],
         "b is contracted while a is a batch -- the case that separates them"),
        ("ijk->ik", [(2, 3, 4)], "one operand with a label summed out"),
    ):
        pairs = [operand(shape, i) for i, shape in enumerate(shapes)]
        cases.append(
            _member_case(
                torch_module, c_module, op,
                f"einsum({equation!r}) [{note}]", "float32", pairs,
                lambda m, *ts, eq=equation: _free(m, "einsum")(eq, *ts),
                note=note,
            )
        )

    # Deliberate gaps, refused by name rather than approximated. Upstream
    # computes all three, so they are `c_error` and flip loudly if a kernel
    # ever lands.
    for equation, shapes, note in (
        ("...c,...c->...", [(2, 3, 4), (2, 3, 4)],
         "an ellipsis stands for a variable number of batch axes"),
        ("ii->i", [(3, 3)], "a repeated label inside one operand is a diagonal"),
    ):
        pairs = [operand(shape, i) for i, shape in enumerate(shapes)]
        cases.append(
            _member_case(
                torch_module, c_module, op,
                f"einsum({equation!r}) [c_error: {note}]", "float32", pairs,
                lambda m, *ts, eq=equation: _free(m, "einsum")(eq, *ts),
                expect="c_error", note=note,
            )
        )
    # A wrong operand count is refused on both sides.
    pairs = [operand((2, 3), 0)]
    cases.append(
        _member_case(
            torch_module, c_module, op,
            "einsum('ij,jk->ik') with one operand [refused]", "float32", pairs,
            lambda m, a: _free(m, "einsum")("ij,jk->ik", a),
            expect="both_error",
            note="the equation names two operands and one was given",
        )
    )
    return cases


def unsafe_view_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten._unsafe_view.default"
    cases: list[Case] = []
    # Deliberately the same shape battery `view_cases` uses. `_unsafe_view` is
    # `view`'s value with a different promise to autograd, and there is no
    # autograd here -- so what these cases pin is that the two keys keep
    # answering the same thing, which is the claim the shared kernel makes.
    for dtype_name in ["float64", "float32", "float16", "bfloat16", "int64", "int32", "uint8"]:
        a_t, a_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4, 5, 6], (2, 3), dtype_name)
        for size, note in [
            ([6], "flatten -- the spelling reshape() emits on a non-contiguous input"),
            ([3, 2], "reshape to a different rank-2 shape"),
            ([-1], "-1 means 'infer this dim's size'"),
            ([1, 2, 3], "add a leading axis"),
        ]:
            cases.append(
                Case(
                    name=f"_unsafe_view(dtype={dtype_name}, (2,3)->{size})",
                    op=op,
                    run_torch=lambda a_t=a_t, size=size: torch_call(a_t, size),
                    run_c=lambda a_c=a_c, size=size: c_module._aten_dispatch(op, a_c, size),
                    note=note,
                )
            )
    return cases


def alias_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.alias.default"
    cases: list[Case] = []
    for dtype_name in ["float64", "float32", "float16", "bfloat16", "int64", "int32", "uint8"]:
        for flat, shape in [([0], ()), ([1, 2, 3], (3,)), ([1, 2, 3, 4], (2, 2))]:
            cases.append(
                _unary_case(
                    torch_module, c_module, op, torch_call, dtype_name, flat, shape,
                    "identity view -- the storage sharing is not reproduced, only the value",
                )
            )
    return cases


_NEG_INT_DTYPES = ["int64", "int32", "int16", "uint8"]


def neg_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.neg.default"
    cases: list[Case] = []
    for dtype_name in _TRIG_DTYPES:
        for flat, shape, note in [
            ([1.0, -2.0, 0.0, 0.5], (2, 2), "assorted signs, including -0.0 from 0.0"),
            ([_FLOAT_ADD_MAGNITUDE[dtype_name], -_FLOAT_ADD_MAGNITUDE[dtype_name]], (2,), "large magnitudes"),
            ([1.5], (), "0-d"),
        ]:
            cases.append(_unary_case(torch_module, c_module, op, torch_call, dtype_name, flat, shape, note))

    for dtype_name in _NEG_INT_DTYPES:
        # `neg` keeps the input dtype -- it does *not* promote an integral
        # input to float the way cos/sin/reciprocal do -- so the integer
        # dtypes are the cases that would catch a wrong helper being reused.
        signed = dtype_name != "uint8"
        flat = [1, -2, 0, 7] if signed else [0, 1, 2, 255]
        note = (
            "signed integers keep their dtype (not promoted to float)"
            if signed
            else "unsigned wraps: neg(uint8 1) == 255, matching torch's modular answer"
        )
        cases.append(_unary_case(torch_module, c_module, op, torch_call, dtype_name, flat, (2, 2), note))

    ut, uc = pair_from_flat(torch_module, c_module, [1, 2], (2,), "uint32")
    cases.append(
        Case(
            name="neg(dtype=uint32) [no neg_cpu kernel upstream]",
            op=op,
            run_torch=lambda: torch_call(ut),
            run_c=lambda: c_module._aten_dispatch(op, uc),
            expect="both_error",
            note="torch: NotImplementedError(\"neg_cpu\" not implemented for 'UInt32'); _C copies the refusal.",
        )
    )

    # Bool is built inside the lambdas rather than shared, the same deferral
    # masked_fill_cases uses -- `_tensor_from_flat` is the only route to a bool
    # tensor in `_C` and it is worth keeping this case's construction failure,
    # if it ever comes back, inside one case instead of the whole harness run.
    cases.append(
        Case(
            name="neg(dtype=bool) [torch points at ~ instead]",
            op=op,
            run_torch=lambda: torch_call(torch_module.tensor([True, False])),
            run_c=lambda: c_module._aten_dispatch(
                op, c_module._tensor_from_flat([1, 0], [2], dtype=c_module.bool)
            ),
            expect="both_error",
            note=(
                "torch: 'Negation, the `-` operator, on a bool tensor is not supported.' "
                "A shim that computed here would turn a mask negation into arithmetic."
            ),
        )
    )
    return cases


def rsub_scalar_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.rsub.Scalar"
    cases: list[Case] = []
    for dtype_name in _TRIG_DTYPES:
        for scalar, alpha, note in [
            (1.0, None, "1 - x, the mask-building shape"),
            (0.0, None, "0 - x, i.e. negation by another spelling"),
            (2.5, 2.0, "alpha scales *self*, not the scalar"),
            (-1.0, -0.5, "negative scalar and negative alpha"),
        ]:
            a_t, a_c = pair_from_flat(
                torch_module, c_module, [1.0, -2.0, 0.0, 0.5], (2, 2), dtype_name
            )
            args = (scalar,) if alpha is None else (scalar, alpha)
            cases.append(
                Case(
                    name=f"rsub(dtype={dtype_name}, other={scalar}, alpha={alpha}) [{note}]",
                    op=op,
                    run_torch=lambda a_t=a_t, args=args: torch_call(a_t, *args),
                    run_c=lambda a_c=a_c, args=args: c_module._aten_dispatch(op, a_c, *args),
                    note=note,
                )
            )

    # The dtype rule, which is `sub.Scalar`'s: an integral tensor stays
    # integral under an int scalar and floats under a float one (torch's
    # "wrapped number" rule), and `uint8` wraps rather than clamping.
    for dtype_name, flat, scalar, alpha, note in [
        ("int64", [1, 2, 3, 4], 5, None, "int tensor, int scalar -> int64"),
        ("int64", [1, 2, 3, 4], 5.0, None, "int tensor, FLOAT scalar -> float32"),
        ("int32", [1, 2, 3, 4], 3, 2, "int32 with alpha=2 -> 3 - 2*x"),
        ("int16", [1, 2, 3, 4], 0, None, "0 - x on int16"),
        ("uint8", [1, 2, 3, 4], 1, None, "unsigned wraps: 1 - 2 == 255"),
    ]:
        a_t, a_c = pair_from_flat(torch_module, c_module, flat, (2, 2), dtype_name)
        args = (scalar,) if alpha is None else (scalar, alpha)
        cases.append(
            Case(
                name=f"rsub(dtype={dtype_name}, other={scalar!r}, alpha={alpha}) [{note}]",
                op=op,
                run_torch=lambda a_t=a_t, args=args: torch_call(a_t, *args),
                run_c=lambda a_c=a_c, args=args: c_module._aten_dispatch(op, a_c, *args),
                note=note,
            )
        )

    cases.append(
        Case(
            name="rsub(dtype=bool) [torch refuses subtraction on masks]",
            op=op,
            run_torch=lambda: torch_call(torch_module.tensor([True, False]), 1),
            run_c=lambda: c_module._aten_dispatch(
                op, c_module._tensor_from_flat([1, 0], [2], dtype=c_module.bool), 1
            ),
            expect="both_error",
            note="torch: 'Subtraction, the `-` operator, with a bool tensor is not supported.'",
        )
    )
    return cases


def silu_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.silu.default"
    cases: list[Case] = []
    for dtype_name in _TRIG_DTYPES:
        for flat, shape, note in [
            ([1.0, -1.0, 0.0, 3.5], (2, 2), "assorted signs -- SwiGLU's gate input"),
            ([-8.0, -4.0, 4.0, 8.0], (2, 2), "saturating tails, where sigmoid rounds to 0/1"),
            ([0.0], (), "0-d"),
        ]:
            cases.append(_unary_case(torch_module, c_module, op, torch_call, dtype_name, flat, shape, note))

    # The refusal, and it is the reason silu is not another `Unary` variant:
    # cos/sin/reciprocal promote an integral input to the default float,
    # silu has no integral kernel upstream at all.
    for dtype_name in ["int64", "int32"]:
        a_t, a_c = pair_from_flat(torch_module, c_module, [1, 2], (2,), dtype_name)
        cases.append(
            Case(
                name=f"silu(dtype={dtype_name}) [no silu_cpu kernel upstream]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c),
                expect="both_error",
                note=(
                    "torch: NotImplementedError(\"silu_cpu\" not implemented for 'Long'). "
                    "Unlike cos/sin, silu does NOT promote an integral input -- a shim "
                    "that reused the unary-float helper here would compute where torch refuses."
                ),
            )
        )
    return cases


def t_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.t.default"
    cases: list[Case] = []
    for dtype_name in ["float64", "float32", "float16", "bfloat16", "int64", "int32", "uint8"]:
        for flat, shape, note in [
            ([5], (), "0-d comes back unchanged"),
            ([1, 2, 3], (3,), "1-d comes back unchanged -- NOT transposed"),
            ([1, 2, 3, 4, 5, 6], (2, 3), "2-d swaps, as nn.Linear's x @ w.t() needs"),
            ([1, 2, 3, 4], (1, 4), "row vector -> column vector"),
        ]:
            cases.append(_unary_case(torch_module, c_module, op, torch_call, dtype_name, flat, shape, note))

    a_t, a_c = pair_from_flat(torch_module, c_module, [1.0] * 24, (2, 3, 4), "float32")
    cases.append(
        Case(
            name="t(3D input rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(a_t),
            run_c=lambda: c_module._aten_dispatch(op, a_c),
            expect="both_error",
            note=(
                "torch: 't() expects a tensor with <= 2 dimensions, but self is 3D'. "
                "t() is not transpose(-2, -1) -- reading it that way would compute on a "
                "batched input where upstream raises."
            ),
        )
    )
    return cases


def _sdpa_pair_check(t_res, c_res) -> tuple[bool, str]:
    """For `_scaled_dot_product_flash_attention_for_cpu`, which returns
    `(output, logsumexp)`.

    Both halves are checked for dtype, shape and value, and the dtypes are
    checked *independently*: for a `float16` input torch answers
    `(float16, float32)`, and that asymmetry is the only externally visible
    evidence that the kernel accumulates in float. Comparing the pair as if
    it shared one dtype would let a shim that computed the whole thing in
    `float16` pass.
    """
    try:
        halves = [(t_res[0], c_res[0], "output"), (t_res[1], c_res[1], "logsumexp")]
    except (TypeError, IndexError, KeyError) as e:
        return False, f"expected a 2-element (output, logsumexp) result on both sides: {e!r}"

    seen = []
    for t_half, c_half, label in halves:
        t_dtype, c_dtype = dt.dtype_name(t_half.dtype), dt.dtype_name(c_half.dtype)
        if t_dtype != c_dtype:
            return False, f"{label} dtype mismatch: torch={t_dtype} c={c_dtype}"
        t_shape = tuple(int(x) for x in t_half.shape)
        c_shape = tuple(int(x) for x in c_half.shape)
        if t_shape != c_shape:
            return False, f"{label} shape mismatch: torch={t_shape} c={c_shape}"
        tol = dt.tolerance_for(t_dtype)
        t_flat, c_flat = _flatten_values(t_half.tolist()), _flatten_values(c_half.tolist())
        if len(t_flat) != len(c_flat):
            return False, f"{label} length differs: torch={len(t_flat)} c={len(c_flat)}"
        for i, (x, y) in enumerate(zip(t_flat, c_flat)):
            xf, yf = float(x), float(y)
            if math.isinf(xf) or math.isinf(yf):
                if xf != yf:
                    return False, f"{label}[{i}] inf mismatch: torch={x!r} c={y!r}"
                continue
            if not math.isclose(xf, yf, rel_tol=tol.rtol, abs_tol=tol.atol):
                return False, f"{label}[{i}] mismatch: torch={x!r} c={y!r}"
        seen.append(f"{label} dtype={t_dtype} shape={t_shape}")
    return True, ", ".join(seen)


_SDPA_DTYPES = ["float64", "float32", "float16", "bfloat16"]


def _sdpa_math_backend_cases(torch_module, c_module, op) -> list[Case]:
    """`F.scaled_dot_product_attention(..., dropout_p > 0)` -- the OTHER backend.

    A non-zero `dropout_p` takes the call off the fused kernel entirely:
    `_scaled_dot_product_flash_attention_for_cpu` refuses dropout, so upstream
    drops to `_scaled_dot_product_attention_math`, a twenty-op sequence
    (docs/TRAIN.md §4). That backend has no dispatch key of its own -- it is
    reached only through the Python function -- so golden is structurally blind
    to it and the cases live under the key of the backend that does have a
    name. `F.scaled_dot_product_attention` is one function; both of its roads
    belong in one builder.

    **THIS BUILDER EXISTS BECAUSE A SABOTAGE PASSED.** Moving the scale from
    "sqrt applied to query AND to key-transposed" to "applied once, after the
    matmul" changed nothing any test could see: the two are algebraically
    equal and differ by about one ULP at ordinary magnitudes, and the training
    sweep's 1e-5 bound is sized to separate dropout MASKS, not to see a
    rounding reorder. The `float16` overflow case below is what sees it, and
    it is the reason upstream splits the scale in the first place: with
    `float16` inputs around 100 the raw `q @ k^T` overflows to `inf` and the
    softmax answers `nan`, while pre-scaling both operands keeps it finite.
    Upstream answers `[12.0, 13.0, 14.0]` there and the scale-once shape
    answers `[nan, nan, nan]` -- measured, on upstream, both ways.
    """
    cases: list[Case] = []

    def sdpa(module):
        return module.nn.functional.scaled_dot_product_attention if hasattr(
            module, "nn") else module._nn.scaled_dot_product_attention

    def seeded(name, dtype_name, shapes, flats, kwargs, note, expect="match",
               value_check=None, seed=17):
        def side(module, which):
            def run():
                if which == "torch":
                    module.manual_seed(seed)
                else:
                    module._shim_manual_seed(seed)
                args = [
                    pair_from_flat(torch_module, c_module, f, sh, dtype_name)[
                        0 if which == "torch" else 1
                    ]
                    for f, sh in zip(flats, shapes)
                ]
                kw = dict(kwargs)
                if "attn_mask" in kw:
                    mf, ms, md = kw.pop("attn_mask")
                    kw["attn_mask"] = pair_from_flat(
                        torch_module, c_module, mf, ms, md
                    )[0 if which == "torch" else 1]
                return sdpa(module)(*args, **kw)

            return run

        return Case(
            name=name,
            op=op,
            run_torch=side(torch_module, "torch"),
            run_c=side(c_module, "c"),
            expect=expect,
            value_check=value_check,
            note=note,
        )

    b, h, t, e = 1, 2, 6, 8
    n = b * h * t * e
    shape = (b, h, t, e)
    q, k, v = _deterministic(n, 21), _deterministic(n, 22), _deterministic(n, 23)

    # 1. The mask itself, seeded, in every dtype the flash path supports. A
    #    shim drawing from the wrong stream lands ~0.4 away here, not 1e-7.
    for dtype_name in _SDPA_DTYPES:
        for kwargs, label in (
            ({"dropout_p": 0.25}, "plain"),
            ({"dropout_p": 0.25, "is_causal": True}, "is_causal"),
            ({"dropout_p": 0.5, "scale": 0.1}, "explicit non-representable scale"),
        ):
            cases.append(
                seeded(
                    f"sdpa_math(dtype={dtype_name}, {kwargs}) [{label}]",
                    dtype_name, [shape] * 3, [q, k, v], kwargs,
                    "the math backend: matmul, mask, _safe_softmax, dropout, matmul",
                )
            )

    # 2. An additive mask with a -inf column, and a boolean one. Both reach
    #    the same `_safe_softmax`; the bool one goes through
    #    `convert_boolean_attn_mask` first.
    mask_shape = (1, 1, t, t)
    add_mask = ([0.0, 0.0, float("-inf"), 0.0, 0.0, 0.0] * t)
    bool_mask = ([1, 1, 0, 1, 1, 1] * t)
    for dtype_name in ["float64", "float32"]:
        cases.append(
            seeded(
                f"sdpa_math(dtype={dtype_name}, additive mask with a -inf column)",
                dtype_name, [shape] * 3, [q, k, v],
                {"dropout_p": 0.25, "attn_mask": (add_mask, mask_shape, dtype_name)},
                "a masked-out column must not become nan -- _safe_softmax's job",
            )
        )
        cases.append(
            seeded(
                f"sdpa_math(dtype={dtype_name}, boolean mask)",
                dtype_name, [shape] * 3, [q, k, v],
                {"dropout_p": 0.25, "attn_mask": (bool_mask, mask_shape, "bool")},
                "True means attend: convert_boolean_attn_mask picks 0.0, not -inf",
            )
        )

    # 3. THE CASE THE SABOTAGE ASKED FOR. float16 inputs at magnitude 100:
    #    `q @ k^T` is 80000, past float16's 65504, so scaling after the matmul
    #    overflows to inf and the softmax answers nan. Splitting the scale
    #    across both operands -- which is what upstream does and why -- keeps
    #    every intermediate finite.
    big = [100.0] * n
    vv = [round(float(i % 7) - 3.0, 4) for i in range(n)]
    for dropout_p in (0.0, 0.25):
        cases.append(
            seeded(
                f"sdpa_math(float16, |q|=|k|=100, dropout_p={dropout_p}) "
                "[scale-once overflows to nan here]",
                "float16", [shape] * 3, [big, big, vv], {"dropout_p": dropout_p},
                "upstream splits the scale as sqrt over BOTH operands for exactly "
                "this: q @ k^T alone is 80000, past float16's 65504",
            )
        )

    # 4. `dropout_p == 1` drops every weight, so the output is exactly zero
    #    whatever the inputs are -- no reference values needed, and a backend
    #    that ignored `dropout_p` would return ordinary attention.
    for dtype_name in ["float32", "bfloat16"]:
        cases.append(
            seeded(
                f"sdpa_math(dtype={dtype_name}, dropout_p=1.0) [exactly zero]",
                dtype_name, [shape] * 3, [q, k, v], {"dropout_p": 1.0},
                "every attention weight is dropped, so the output is 0 -- the one "
                "assertion about this path that needs no reference values",
                value_check=_signed_zero_check,
            )
        )

    # 5. Upstream's own refusal, which the math backend raises and the flash
    #    path never reaches.
    cases.append(
        seeded(
            "sdpa_math(is_causal AND an explicit mask) [refused on both sides]",
            "float32", [shape] * 3, [q, k, v],
            {"dropout_p": 0.25, "is_causal": True,
             "attn_mask": (add_mask, mask_shape, "float32")},
            "torch: '_scaled_dot_product_attention: Explicit attn_mask should not "
            "be set when is_causal=True' -- the math backend builds its own",
            expect="both_error",
        )
    )
    return cases


def sdpa_flash_cpu_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten._scaled_dot_product_flash_attention_for_cpu.default"
    cases: list[Case] = _sdpa_math_backend_cases(torch_module, c_module, op)

    b, h, t, e = 1, 2, 3, 4
    n = b * h * t * e
    q_flat, k_flat, v_flat = _deterministic(n, 1), _deterministic(n, 2), _deterministic(n, 3)
    shape = (b, h, t, e)

    for dtype_name in _SDPA_DTYPES:
        for extra_args, kwargs, note in [
            ((0.0, False), {}, "plain attention, default scale = 1/sqrt(head_dim)"),
            ((0.0, True), {}, "is_causal -- upper-left aligned, measured not assumed"),
            ((0.0, False), {"scale": 0.25}, "explicit scale overrides 1/sqrt(head_dim)"),
        ]:
            q_t, q_c = pair_from_flat(torch_module, c_module, q_flat, shape, dtype_name)
            k_t, k_c = pair_from_flat(torch_module, c_module, k_flat, shape, dtype_name)
            v_t, v_c = pair_from_flat(torch_module, c_module, v_flat, shape, dtype_name)
            cases.append(
                Case(
                    name=f"sdpa_flash_cpu(dtype={dtype_name}, args={extra_args}, kwargs={kwargs}) [{note}]",
                    op=op,
                    run_torch=lambda q_t=q_t, k_t=k_t, v_t=v_t, extra_args=extra_args, kwargs=kwargs: torch_call(
                        q_t, k_t, v_t, *extra_args, **kwargs
                    ),
                    run_c=lambda q_c=q_c, k_c=k_c, v_c=v_c, extra_args=extra_args, kwargs=kwargs: c_module._aten_dispatch(
                        op, q_c, k_c, v_c, *extra_args, **kwargs
                    ),
                    value_check=_sdpa_pair_check,
                    note=note + " -- (output, logsumexp), see _sdpa_pair_check",
                )
            )

    # An additive mask, including a `-inf` column: this is how a padding or
    # causal mask actually arrives from transformers, and it is the case that
    # proves the softmax subtracts the row maximum first -- without that,
    # `exp(-inf)` and `exp(large)` both land on NaN.
    mask_shape = (1, 1, t, t)
    mask_flat = [0.0, 0.0, float("-inf")] * t
    for dtype_name in ["float64", "float32"]:
        for is_causal, note in [
            (False, "additive mask with a -inf column"),
            (True, "is_causal AND attn_mask together -- upstream composes them, measured"),
        ]:
            q_t, q_c = pair_from_flat(torch_module, c_module, q_flat, shape, dtype_name)
            k_t, k_c = pair_from_flat(torch_module, c_module, k_flat, shape, dtype_name)
            v_t, v_c = pair_from_flat(torch_module, c_module, v_flat, shape, dtype_name)
            m_t, m_c = pair_from_flat(torch_module, c_module, mask_flat, mask_shape, dtype_name)
            cases.append(
                Case(
                    name=f"sdpa_flash_cpu(dtype={dtype_name}, attn_mask, is_causal={is_causal}) [{note}]",
                    op=op,
                    run_torch=lambda q_t=q_t, k_t=k_t, v_t=v_t, m_t=m_t, is_causal=is_causal: torch_call(
                        q_t, k_t, v_t, 0.0, is_causal, attn_mask=m_t
                    ),
                    run_c=lambda q_c=q_c, k_c=k_c, v_c=v_c, m_c=m_c, is_causal=is_causal: c_module._aten_dispatch(
                        op, q_c, k_c, v_c, 0.0, is_causal, attn_mask=m_c
                    ),
                    value_check=_sdpa_pair_check,
                    note=note,
                )
            )

    # Key/value longer than query, causal. This is the shape a decode step with
    # a KV cache has, and it is where the two possible readings of `is_causal`
    # disagree: upper-left (row i attends keys 0..i) vs bottom-right (row i
    # attends keys 0..i+kv-q). Every element differs between them.
    kv = 5
    q2 = _deterministic(1 * 1 * 2 * e, 4)
    k2 = _deterministic(1 * 1 * kv * e, 5)
    v2 = _deterministic(1 * 1 * kv * e, 6)
    for dtype_name in ["float64", "float32"]:
        q_t, q_c = pair_from_flat(torch_module, c_module, q2, (1, 1, 2, e), dtype_name)
        k_t, k_c = pair_from_flat(torch_module, c_module, k2, (1, 1, kv, e), dtype_name)
        v_t, v_c = pair_from_flat(torch_module, c_module, v2, (1, 1, kv, e), dtype_name)
        cases.append(
            Case(
                name=f"sdpa_flash_cpu(dtype={dtype_name}, q_len=2, kv_len=5, is_causal=True)",
                op=op,
                run_torch=lambda q_t=q_t, k_t=k_t, v_t=v_t: torch_call(q_t, k_t, v_t, 0.0, True),
                run_c=lambda q_c=q_c, k_c=k_c, v_c=v_c: c_module._aten_dispatch(
                    op, q_c, k_c, v_c, 0.0, True
                ),
                value_check=_sdpa_pair_check,
                note="pins the causal alignment: upper-left, not bottom-right",
            )
        )

    # The other side of that shape -- MORE query rows than keys, causal. Rows
    # past the last key attend all of them, so the mask stops widening part way
    # down and every row below it is entirely unmasked. Both causal cases above
    # have `q_len <= kv_len` and never reach that, which left the clamp in
    # `tensor.rs::scale_and_mask_rows` (`keep = (r + 1).min(cols)`) with no
    # case at all: without it the kernel indexes past the end of the row.
    # Upstream accepts this shape and answers finitely -- measured at three
    # shapes before these cases were written. docs/SEQLEN.md §8.
    for q_len, kv_len in [(5, 2), (9, 3)]:
        qn = _deterministic(1 * 2 * q_len * e, 7)
        kn = _deterministic(1 * 2 * kv_len * e, 8)
        vn = _deterministic(1 * 2 * kv_len * e, 9)
        for dtype_name in ["float64", "float32"]:
            q_t, q_c = pair_from_flat(torch_module, c_module, qn, (1, 2, q_len, e), dtype_name)
            k_t, k_c = pair_from_flat(torch_module, c_module, kn, (1, 2, kv_len, e), dtype_name)
            v_t, v_c = pair_from_flat(torch_module, c_module, vn, (1, 2, kv_len, e), dtype_name)
            cases.append(
                Case(
                    name=f"sdpa_flash_cpu(dtype={dtype_name}, q_len={q_len}, "
                    f"kv_len={kv_len}, is_causal=True)",
                    op=op,
                    run_torch=lambda q_t=q_t, k_t=k_t, v_t=v_t: torch_call(
                        q_t, k_t, v_t, 0.0, True
                    ),
                    run_c=lambda q_c=q_c, k_c=k_c, v_c=v_c: c_module._aten_dispatch(
                        op, q_c, k_c, v_c, 0.0, True
                    ),
                    value_check=_sdpa_pair_check,
                    note="more query rows than keys -- the causal mask stops widening "
                    "part way down, the only shape that exercises the clamp",
                )
            )

    # A causal block several rows deep with a scale that is not representable.
    # `0.1` is the value at which narrowing the scale after the multiply rather
    # than before gives a different `float32` -- the fault docs/SEQLEN.md §8.4
    # lists seventh -- and the three-by-three cases above all use the default
    # `1/sqrt(head_dim)`, which for `head_dim=4` is exactly 0.5.
    wide = 9
    for dtype_name in ["float64", "float32"]:
        qn = _deterministic(1 * 2 * wide * e, 10)
        kn = _deterministic(1 * 2 * wide * e, 11)
        vn = _deterministic(1 * 2 * wide * e, 12)
        q_t, q_c = pair_from_flat(torch_module, c_module, qn, (1, 2, wide, e), dtype_name)
        k_t, k_c = pair_from_flat(torch_module, c_module, kn, (1, 2, wide, e), dtype_name)
        v_t, v_c = pair_from_flat(torch_module, c_module, vn, (1, 2, wide, e), dtype_name)
        cases.append(
            Case(
                name=f"sdpa_flash_cpu(dtype={dtype_name}, 9x9 is_causal, scale=0.1)",
                op=op,
                run_torch=lambda q_t=q_t, k_t=k_t, v_t=v_t: torch_call(
                    q_t, k_t, v_t, 0.0, True, scale=0.1
                ),
                run_c=lambda q_c=q_c, k_c=k_c, v_c=v_c: c_module._aten_dispatch(
                    op, q_c, k_c, v_c, 0.0, True, scale=0.1
                ),
                value_check=_sdpa_pair_check,
                note="a scale that is not representable, over a mask several rows deep",
            )
        )

    # The refusals, all four measured on upstream first.
    q_t, q_c = pair_from_flat(torch_module, c_module, q_flat, shape, "float32")
    k_t, k_c = pair_from_flat(torch_module, c_module, k_flat, shape, "float32")
    v_t, v_c = pair_from_flat(torch_module, c_module, v_flat, shape, "float32")
    cases.append(
        Case(
            name="sdpa_flash_cpu(dropout_p=0.5 rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(q_t, k_t, v_t, 0.5, False),
            run_c=lambda: c_module._aten_dispatch(op, q_c, k_c, v_c, 0.5, False),
            expect="both_error",
            note=(
                "torch: 'Currently do not support dropout > 0'. The shim refuses for the "
                "same reason upstream does, not for want of an RNG."
            ),
        )
    )

    q3_t, q3_c = pair_from_flat(torch_module, c_module, _deterministic(h * t * e, 7), (h, t, e), "float32")
    cases.append(
        Case(
            name="sdpa_flash_cpu(3D input rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(q3_t, q3_t, q3_t, 0.0, False),
            run_c=lambda: c_module._aten_dispatch(op, q3_c, q3_c, q3_c, 0.0, False),
            expect="both_error",
            note="torch: 'Accept only 4 dims inputs shape of {B, H, T, K}'.",
        )
    )

    qi_t, qi_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4] * (n // 4), shape, "int64")
    cases.append(
        Case(
            name="sdpa_flash_cpu(int64 input rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(qi_t, qi_t, qi_t, 0.0, False),
            run_c=lambda: c_module._aten_dispatch(op, qi_c, qi_c, qi_c, 0.0, False),
            expect="both_error",
            note="torch: 'Expected data type in FP32, FP64, BF16, FP16, but got Long instead.'",
        )
    )

    m64_t, m64_c = pair_from_flat(torch_module, c_module, [0.0] * (t * t), mask_shape, "float64")
    cases.append(
        Case(
            name="sdpa_flash_cpu(float32 query with float64 mask rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(q_t, k_t, v_t, 0.0, False, attn_mask=m64_t),
            run_c=lambda: c_module._aten_dispatch(op, q_c, k_c, v_c, 0.0, False, attn_mask=m64_c),
            expect="both_error",
            note="torch: 'Attention mask is the same data type as query'.",
        )
    )
    cases.extend(_sdpa_gqa_cases(torch_module, c_module, torch_call))

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # query/key/dropout_p/is_causal/scale all by keyword (value stays
    # positional -- it is not in `interned_name`'s table).
    kw_q_t, kw_q_c = pair_from_flat(torch_module, c_module, q_flat, shape, "float32")
    kw_k_t, kw_k_c = pair_from_flat(torch_module, c_module, k_flat, shape, "float32")
    kw_v_t, kw_v_c = pair_from_flat(torch_module, c_module, v_flat, shape, "float32")
    cases.append(
        Case(
            name="sdpa_flash_cpu(query=/key=/dropout_p=/is_causal=/scale= all by keyword)",
            op=op,
            run_torch=lambda: torch_call(
                query=kw_q_t, key=kw_k_t, value=kw_v_t, dropout_p=0.0, is_causal=False, scale=0.25
            ),
            run_c=lambda: c_module._aten_dispatch(
                op, query=kw_q_c, key=kw_k_c, value=kw_v_c, dropout_p=0.0, is_causal=False, scale=0.25
            ),
            value_check=_sdpa_pair_check,
        )
    )
    return cases


# --- grouped-query attention: the aten op broadcasts the KV head dimension ---
#
# SmolLM2-135M is `num_attention_heads=9, num_key_value_heads=3`, so a real
# pretrained forward goes down this path and nothing in the Llama/GPT-2 work
# before it did (docs/CKPT2.md §7.1).
#
# Where the repetition belongs was MEASURED, and the answer is "here, in the
# aten op" -- not in `F.scaled_dot_product_attention`:
#
#   * a `TorchDispatchMode` over `F.scaled_dot_product_attention(q, k, v,
#     enable_gqa=True)` with q=(2,9,4,8) and k=v=(2,3,4,8) reports exactly one
#     op, `aten._scaled_dot_product_flash_attention_for_cpu.default`, with the
#     key and value STILL (2,3,4,8). Nothing repeats them on the way in.
#   * calling the aten op directly with those mismatched shapes -- no
#     `enable_gqa` argument exists at this level -- answers (2,9,4,8), and
#     matches `enable_gqa=True` to 0.0.
#
# So the aten op always broadcasts and has no flag; `enable_gqa` is a
# validation switch in the Python-level wrapper, and that half is tested in
# rust/torch_c/pytests/test_shim.py where the wrapper lives.
#
# **Which repetition** is the part that fails plausibly rather than loudly.
# Measured three ways on q=(2,9,4,8), k=v=(2,3,4,8):
#
#     repeat_interleave(3, dim=1)             0.0
#     transformers' repeat_kv (expand+reshape) 0.0
#     repeat(1, 3, 1, 1)  ("tile")             2.82
#
# Both correct spellings give query head `i` the key/value head `i // 3`;
# tiling gives it `i % 3`. Tiling produces a same-shaped, same-magnitude,
# entirely wrong answer -- the failure mode docs/ARCH.md's `gelu` note calls
# out, where the logits look fine and are not. The two GQA cases below are
# built so that the two readings disagree: `n_rep` is 3 and every KV head
# carries different numbers, so `i // 3` and `i % 3` select different rows
# for six of the nine query heads.


def _sdpa_gqa_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten._scaled_dot_product_flash_attention_for_cpu.default"
    cases: list[Case] = []
    b, e = 1, 4

    for h_q, h_kv, t, s, is_causal, note in [
        (9, 3, 4, 4, False, "SmolLM2-135M's own head counts: 9 query heads, 3 KV heads"),
        (9, 3, 4, 4, True, "the same, causal -- the mask is per (row, col), not per head"),
        (4, 1, 3, 3, False, "multi-query attention: ONE KV head broadcast to all four"),
        (2, 2, 3, 3, False, "n_rep == 1 -- the matched case must not regress"),
        (6, 3, 2, 5, True, "kv longer than q AND grouped: both broadcasts at once"),
    ]:
        q_flat = _deterministic(b * h_q * t * e, 11)
        k_flat = _deterministic(b * h_kv * s * e, 12)
        v_flat = _deterministic(b * h_kv * s * e, 13)
        for dtype_name in ["float64", "float32"]:
            q_t, q_c = pair_from_flat(torch_module, c_module, q_flat, (b, h_q, t, e), dtype_name)
            k_t, k_c = pair_from_flat(torch_module, c_module, k_flat, (b, h_kv, s, e), dtype_name)
            v_t, v_c = pair_from_flat(torch_module, c_module, v_flat, (b, h_kv, s, e), dtype_name)
            cases.append(
                Case(
                    name=f"sdpa_flash_cpu(GQA dtype={dtype_name}, h_q={h_q}, h_kv={h_kv}, "
                         f"t={t}, s={s}, is_causal={is_causal}) [{note}]",
                    op=op,
                    run_torch=lambda q_t=q_t, k_t=k_t, v_t=v_t, is_causal=is_causal: torch_call(
                        q_t, k_t, v_t, 0.0, is_causal
                    ),
                    run_c=lambda q_c=q_c, k_c=k_c, v_c=v_c, is_causal=is_causal: (
                        c_module._aten_dispatch(op, q_c, k_c, v_c, 0.0, is_causal)
                    ),
                    value_check=_sdpa_pair_check,
                    note=note,
                )
            )

    # A grouped call with an additive mask, because the mask is indexed by
    # (batch, head, row, col) and a kernel that repeated the heads AFTER
    # adding the mask would broadcast a (1,1,T,S) mask fine and a per-head
    # one wrong. This mask is per-head over the NINE query heads, which only
    # exists after the repetition.
    h_q, h_kv, t, s = 9, 3, 4, 4
    q_flat = _deterministic(b * h_q * t * e, 11)
    k_flat = _deterministic(b * h_kv * s * e, 12)
    v_flat = _deterministic(b * h_kv * s * e, 13)
    mask_flat = _deterministic(b * h_q * t * s, 14)
    for dtype_name in ["float64", "float32"]:
        q_t, q_c = pair_from_flat(torch_module, c_module, q_flat, (b, h_q, t, e), dtype_name)
        k_t, k_c = pair_from_flat(torch_module, c_module, k_flat, (b, h_kv, s, e), dtype_name)
        v_t, v_c = pair_from_flat(torch_module, c_module, v_flat, (b, h_kv, s, e), dtype_name)
        m_t, m_c = pair_from_flat(torch_module, c_module, mask_flat, (b, h_q, t, s), dtype_name)
        cases.append(
            Case(
                name=f"sdpa_flash_cpu(GQA dtype={dtype_name}, PER-QUERY-HEAD attn_mask)",
                op=op,
                run_torch=lambda q_t=q_t, k_t=k_t, v_t=v_t, m_t=m_t: torch_call(
                    q_t, k_t, v_t, 0.0, False, attn_mask=m_t
                ),
                run_c=lambda q_c=q_c, k_c=k_c, v_c=v_c, m_c=m_c: c_module._aten_dispatch(
                    op, q_c, k_c, v_c, 0.0, False, attn_mask=m_c
                ),
                value_check=_sdpa_pair_check,
                note="the mask has 9 head rows, which only exist after the KV heads are "
                     "repeated -- pins the ORDER of repetition and masking",
            )
        )

    # Non-divisible head counts. The aten op does not refuse these -- it
    # answers, deterministically, and the answer is partly garbage. Measured
    # per query head against `kv_head = q_head // (h_q // h_kv)`:
    #
    #     h_q=9 h_kv=4   heads 0..7 agree to 0.0, head 8 differs by 0.93
    #     h_q=9 h_kv=2   heads 0..7 agree to 0.0, head 8 differs by 2.28
    #     h_q=6 h_kv=4   heads 0..3 agree to 0.0, head 4 by 0.78,
    #                    head 5 by 2.38e+31
    #
    # That is the same rule as the divisible case for the first
    # `h_kv * (h_q // h_kv)` heads and an out-of-bounds read for the
    # remainder -- 2.38e+31 is not a number an attention output can take with
    # unit-magnitude inputs. So there is nothing here to reproduce, and the
    # shim refuses by name instead. `c_error`, not `both_error`: torch really
    # does return a tensor, and pretending otherwise would misdescribe it.
    #
    # This is reachable only by calling the aten op directly. Every caller
    # that goes through `F.scaled_dot_product_attention` is stopped one layer
    # up by the divisibility check, which upstream also has and which
    # test_shim.py covers.
    for h_q, h_kv, note in [
        (9, 2, "remainder head reads past the end of the KV tensor"),
        (9, 4, "same, one leftover head"),
        (4, 6, "more KV heads than query heads -- no repetition exists"),
    ]:
        q_flat = _deterministic(b * h_q * 3 * e, 21)
        kv_flat = _deterministic(b * h_kv * 3 * e, 22)
        q_t, q_c = pair_from_flat(torch_module, c_module, q_flat, (b, h_q, 3, e), "float64")
        k_t, k_c = pair_from_flat(torch_module, c_module, kv_flat, (b, h_kv, 3, e), "float64")
        cases.append(
            Case(
                name=f"sdpa_flash_cpu(h_q={h_q}, h_kv={h_kv} -- NOT divisible) [{note}]",
                op=op,
                run_torch=lambda q_t=q_t, k_t=k_t: torch_call(q_t, k_t, k_t, 0.0, False),
                run_c=lambda q_c=q_c, k_c=k_c: c_module._aten_dispatch(
                    op, q_c, k_c, k_c, 0.0, False
                ),
                expect="c_error",
                note="torch answers with a partly out-of-bounds result; the shim refuses "
                     "by name rather than reproducing uninitialised memory -- " + note,
            )
        )
    cases.extend(_sdpa_block_cases(torch_module, c_module, torch_call))
    return cases


# --- the shapes that cross the kernel's own block boundaries ----------------
#
# Every sdpa case above is 3 or 5 keys long, which is shorter than any block
# `aten::_scaled_dot_product_flash_attention_for_cpu` splits on. So they all
# take one path through it -- one query block, one key block, no online
# rescale -- and the blocked structure the kernel is named for went
# unexercised by this harness for as long as the op has been in it.
#
# The three boundaries, and the shape here that crosses each:
#
#   32 query rows    the block size the kernel picks for short queries;
#                    q_len=33 makes a second block run, with the first
#                    block's row maximum carried into it
#   512 key columns  the key split; kv_len=600 makes the online rescale run,
#                    which is the only path that multiplies the accumulator
#                    by `exp(previous_max - this_max)`
#   8 mask lanes     the fused `qk * scale + mask` strides by the *mask*
#                    dtype's vector width; kv_len=70 leaves a six-column
#                    remainder that is fused where the body is not
#
# These are tolerance checks like every other case in this file. The exact
# ones live in `pytests/test_shim.py` -- see the section comment there for why
# one bfloat16 ulp is invisible to `dtypes.py::TOLERANCES`, and what that cost.
#
# **These sixteen run with the reference kernel switched on; the sdpa cases
# above do not.** `crate::flash` is opt-in because it costs 20x (docs/SDPA.md
# §7), so each case here asks for it in `run_c` and puts the switch back. The
# split is deliberate rather than left over: the cases before this point are
# the only coverage the *default* path has in this harness, and moving them
# across would leave the path every forward pass actually takes unmeasured
# here. Boundaries are what these sixteen are for, and a boundary inside a
# blocked kernel does not exist on a path that has no blocks.
def _sdpa_block_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten._scaled_dot_product_flash_attention_for_cpu.default"
    cases: list[Case] = []
    e = 8

    def with_reference(call):
        """Wraps a `run_c` so it selects `crate::flash`, and restores after.

        Restores the *previous* value rather than `False`, so a whole run under
        `BW_SDPA_REFERENCE=1` is not undone case by case. The `finally` matters
        more than it looks: `compare.py --inject-fault` and `--self-test`
        deliberately make cases fail, and a switch left on by a raised
        exception would quietly move every case after this section onto a path
        20x slower than the one they are meant to measure.
        """

        def run():
            was = c_module._shim_sdpa_reference(True)
            try:
                return call()
            finally:
                c_module._shim_sdpa_reference(was)

        return run

    for dtype_name in _SDPA_DTYPES:
        for q_len, kv_len, use_mask, is_causal, note in [
            (33, 33, False, False, "33 query rows -- a second 32-row query block"),
            (33, 33, False, True, "second query block, causal"),
            (70, 70, True, False, "70 keys with a mask -- six columns past the mask's eight lanes"),
            (20, 600, False, False, "600 keys -- past the 512-column key split"),
        ]:
            q_flat = _deterministic(q_len * e, 31)
            k_flat = _deterministic(kv_len * e, 32)
            v_flat = _deterministic(kv_len * e, 33)
            q_t, q_c = pair_from_flat(torch_module, c_module, q_flat, (1, 1, q_len, e), dtype_name)
            k_t, k_c = pair_from_flat(torch_module, c_module, k_flat, (1, 1, kv_len, e), dtype_name)
            v_t, v_c = pair_from_flat(torch_module, c_module, v_flat, (1, 1, kv_len, e), dtype_name)
            kw_t: dict = {}
            kw_c: dict = {}
            if use_mask:
                mask_flat = _deterministic(q_len * kv_len, 34)
                # Every seventh column masked out entirely: a padding mask's
                # shape, and the reason the kernel writes zeros rather than
                # `exp(-inf - -inf)`.
                for i in range(0, len(mask_flat), 7):
                    mask_flat[i] = float("-inf")
                m_t, m_c = pair_from_flat(
                    torch_module, c_module, mask_flat, (1, 1, q_len, kv_len), dtype_name
                )
                kw_t["attn_mask"] = m_t
                kw_c["attn_mask"] = m_c
            cases.append(
                Case(
                    name=(
                        f"sdpa_flash_cpu(dtype={dtype_name}, q_len={q_len}, "
                        f"kv_len={kv_len}, mask={use_mask}, is_causal={is_causal}) [{note}]"
                    ),
                    op=op,
                    run_torch=lambda q_t=q_t, k_t=k_t, v_t=v_t, is_causal=is_causal, kw_t=kw_t: (
                        torch_call(q_t, k_t, v_t, 0.0, is_causal, **kw_t)
                    ),
                    run_c=with_reference(
                        lambda q_c=q_c, k_c=k_c, v_c=v_c, is_causal=is_causal, kw_c=kw_c: (
                            c_module._aten_dispatch(op, q_c, k_c, v_c, 0.0, is_causal, **kw_c)
                        )
                    ),
                    value_check=_sdpa_pair_check,
                    note=note,
                )
            )
    return cases


# --- the eight ops `do_sample=True` stops on (docs/SAMPLING.md) --------------
#
# docs/GAP.md §4 predicted ten; the coordinating session re-measured a real
# transformers Llama with `TorchDispatchMode` and found eight `_aten_dispatch`
# still refused. These are their cases.
#
# Every builder below defers tensor construction into the `run_torch`/`run_c`
# lambdas, the way `masked_fill_cases` does. For the in-place `fill_.Tensor`
# that is load-bearing (a shared operand would carry one case's mutation into
# the next); for the rest it is uniformity, and it keeps a builder from being
# able to crash the whole harness at case-list time.


def _pair(torch_module, c_module, flat, shape, dtype_name):
    """The two operands, built fresh. Same numbers on both sides by
    construction -- see build.pair_from_flat, which this is the deferred form
    of."""
    return pair_from_flat(torch_module, c_module, flat, shape, dtype_name)


# --- aten._softmax.default ---------------------------------------------------
#
# `_softmax` is the op behind `nn.functional.softmax`, and in the sampling loop
# it is what turns logits into the probability vector `multinomial` draws from.
#
# Both of its refusals are reproduced and both are pinned here, because each
# would otherwise be a silent success:
#
#   * `half_to_float=True` raises on CPU for *every* dtype -- float16,
#     bfloat16 and float32 alike (measured). It is a CUDA-only fusion. A shim
#     that honoured it would answer float32 where upstream raises.
#   * an integral input raises `NotImplementedError` naming the kernel, not a
#     `RuntimeError`.
#
# The `-inf` cases are the ones that matter numerically: a masked attention
# row and an all-masked row are both real inputs, and the max-subtraction is
# the only thing standing between the first one and a NaN.

_SOFTMAX_DTYPES = ["float64", "float32", "float16", "bfloat16"]


def softmax_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten._softmax.default"
    cases: list[Case] = []
    scenarios = [
        ([1.0, 2.0, 3.0, 0.0, 0.0, 0.0], (2, 3), -1, "last dim -- the vectorised path"),
        ([1.0, 2.0, 3.0, 0.0, 0.0, 0.0], (2, 3), 0, "first dim -- the strided path"),
        ([1.0, 2.0, 3.0], (3,), 0, "1-D"),
        ([3.0], (), -1, "0-d: the single element is the whole distribution, so 1.0"),
    ]
    for dtype_name in _SOFTMAX_DTYPES:
        for flat, shape, dim, note in scenarios:
            cases.append(
                Case(
                    name=f"_softmax(dtype={dtype_name}, shape={shape}, dim={dim}) [{note}]",
                    op=op,
                    run_torch=lambda flat=flat, shape=shape, dim=dim, dtype_name=dtype_name: torch_call(
                        _pair(torch_module, c_module, flat, shape, dtype_name)[0], dim, False
                    ),
                    run_c=lambda flat=flat, shape=shape, dim=dim, dtype_name=dtype_name: c_module._aten_dispatch(
                        op, _pair(torch_module, c_module, flat, shape, dtype_name)[1], dim, False
                    ),
                    note=note,
                )
            )

    edge = [
        ([1.0, float("-inf"), 2.0], (3,), "one masked position",
         "exp(-inf - max) is a clean zero only because the max is subtracted first"),
        ([float("-inf"), float("-inf")], (2,), "a fully masked row",
         "NaN on both sides, and that agreement is the point"),
        ([1000.0, 1001.0, 999.0], (3,), "large logits",
         "without the max subtraction every exp overflows to inf"),
        ([], (0,), "empty", "no lane to reduce"),
    ]
    for flat, shape, label, note in edge:
        cases.append(
            Case(
                name=f"_softmax(float32, {label})",
                op=op,
                run_torch=lambda flat=flat, shape=shape: torch_call(
                    _pair(torch_module, c_module, flat, shape, "float32")[0], -1, False
                ),
                run_c=lambda flat=flat, shape=shape: c_module._aten_dispatch(
                    op, _pair(torch_module, c_module, flat, shape, "float32")[1], -1, False
                ),
                note=note,
            )
        )

    for dtype_name, why in [
        ("float32", "torch: 'softmax with half to float conversion is not supported on CPU'"),
        ("float16", "the same refusal, for the dtype whose name the flag comes from"),
    ]:
        cases.append(
            Case(
                name=f"_softmax(dtype={dtype_name}, half_to_float=True rejected on both sides)",
                op=op,
                run_torch=lambda dtype_name=dtype_name: torch_call(
                    _pair(torch_module, c_module, [1.0, 2.0, 3.0], (3,), dtype_name)[0], -1, True
                ),
                run_c=lambda dtype_name=dtype_name: c_module._aten_dispatch(
                    op, _pair(torch_module, c_module, [1.0, 2.0, 3.0], (3,), dtype_name)[1], -1, True
                ),
                expect="both_error",
                note=why,
            )
        )
    cases.append(
        Case(
            name="_softmax(int64 rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [1, 2, 3], (3,), "int64")[0], -1, False
            ),
            run_c=lambda: c_module._aten_dispatch(
                op, _pair(torch_module, c_module, [1, 2, 3], (3,), "int64")[1], -1, False
            ),
            expect="both_error",
            note='torch: NotImplementedError, "softmax_lastdim_kernel_impl" not implemented for \'Long\'',
        )
    )
    cases.append(
        Case(
            name="_softmax(dim out of range rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [1.0, 2.0, 3.0], (3,), "float32")[0], 5, False
            ),
            run_c=lambda: c_module._aten_dispatch(
                op, _pair(torch_module, c_module, [1.0, 2.0, 3.0], (3,), "float32")[1], 5, False
            ),
            expect="both_error",
            note="IndexError on both sides",
        )
    )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # self/dim/half_to_float all by keyword.
    kw_t, kw_c = _pair(torch_module, c_module, [1.0, 2.0, 3.0, 0.0, 0.0, 0.0], (2, 3), "float32")
    cases.append(
        Case(
            name="_softmax(self=/dim=/half_to_float= all by keyword)",
            op=op,
            run_torch=lambda: torch_call(self=kw_t, dim=-1, half_to_float=False),
            run_c=lambda: c_module._aten_dispatch(op, self=kw_c, dim=-1, half_to_float=False),
        )
    )
    return cases


# --- aten.le.Scalar ----------------------------------------------------------
# The same family as lt/eq/ne above; `x <= v` keeps the Python number as a
# Scalar rather than lifting it to a tensor. Reached by the repetition-penalty
# and min-length warpers.


def le_scalar_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.le.Scalar"
    cases: list[Case] = []
    for dtype_name in _CMP_DTYPES:
        cases.append(
            _binary_scalar_case(
                torch_module, c_module, op, torch_call, dtype_name,
                [1, 2, 3, 4], (2, 2), 3,
                "x <= 3, as reached from __le__ with a python scalar -- note 3 itself is "
                "included, which is the whole difference from lt.Scalar",
            )
        )
    cases.append(
        Case(
            name="le(float32, nan <= 1.0) [every comparison against NaN is false]",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [float("nan"), 1.0], (2,), "float32")[0], 1.0
            ),
            run_c=lambda: c_module._aten_dispatch(
                op, _pair(torch_module, c_module, [float("nan"), 1.0], (2,), "float32")[1], 1.0
            ),
            note="NaN is not <= anything, including itself",
        )
    )
    return cases


# --- aten.squeeze.dim --------------------------------------------------------
#
# The generation loop's `next_tokens.squeeze(1)`. The rule that has to be right
# is the one that looks like a bug: **a dimension whose size is not 1 is a
# no-op, not an error** (measured). Refusing there would break the loop the
# moment a batch had a single row.


def squeeze_dim_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.squeeze.dim"
    cases: list[Case] = []
    flat, shape = [0.0, 1.0, 2.0, 3.0, 4.0, 5.0], (1, 3, 1, 2)
    for dim, note in [
        (0, "leading size-1 dim removed"),
        (2, "interior size-1 dim removed"),
        (1, "size 3 -- NO-OP, not an error"),
        (-1, "size 2 via a negative dim -- also a no-op"),
        (-4, "the leading dim again, addressed from the end"),
    ]:
        cases.append(
            Case(
                name=f"squeeze({shape}, dim={dim}) [{note}]",
                op=op,
                run_torch=lambda dim=dim: torch_call(
                    _pair(torch_module, c_module, flat, shape, "float32")[0], dim
                ),
                run_c=lambda dim=dim: c_module._aten_dispatch(
                    op, _pair(torch_module, c_module, flat, shape, "float32")[1], dim
                ),
                note=note,
            )
        )
    for dtype_name in ["float64", "float32", "int64", "uint8"]:
        cases.append(
            Case(
                name=f"squeeze(dtype={dtype_name}, (2,1) dim=1)",
                op=op,
                run_torch=lambda dtype_name=dtype_name: torch_call(
                    _pair(torch_module, c_module, [1, 2], (2, 1), dtype_name)[0], 1
                ),
                run_c=lambda dtype_name=dtype_name: c_module._aten_dispatch(
                    op, _pair(torch_module, c_module, [1, 2], (2, 1), dtype_name)[1], 1
                ),
                note="the shape the sampling loop actually squeezes: (batch, 1) -> (batch,)",
            )
        )
    cases.append(
        Case(
            name="squeeze(0-d, dim=0) [torch accepts dim 0 and -1 on a 0-d tensor]",
            op=op,
            run_torch=lambda: torch_call(_pair(torch_module, c_module, [5.0], (), "float32")[0], 0),
            run_c=lambda: c_module._aten_dispatch(
                op, _pair(torch_module, c_module, [5.0], (), "float32")[1], 0
            ),
            note="nothing to remove, so the 0-d tensor comes back unchanged",
        )
    )
    cases.append(
        Case(
            name="squeeze(dim out of range rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(_pair(torch_module, c_module, flat, shape, "float32")[0], 9),
            run_c=lambda: c_module._aten_dispatch(
                op, _pair(torch_module, c_module, flat, shape, "float32")[1], 9
            ),
            expect="both_error",
            note="IndexError on both sides -- a no-op dim is not the same as a nonexistent one",
        )
    )
    return cases


# --- aten.sort.default / aten.topk.default -----------------------------------
#
# Both answer a (values, indices) pair, so both reuse `_pair_result_check`.
# What they do *not* share is how far the agreement goes, and that difference
# is measured, not assumed:
#
#   * **`sort` is stable, in both directions.** `[3,1,3,1,2,3]` descending
#     answers indices `[0,2,5,4,1,3]` -- the three 3.0s in increasing index
#     order, not reversed. An 80-element all-ties tensor comes back as
#     `0..79`. So ties can be compared exactly and are.
#   * **`topk` is a partial selection and its tie order is not stable.** On
#     that same input `k=3` agrees with a stable sort (`[0,2,5]`) but `k=6`
#     does not: upstream answers `[0,2,5,4,3,1]`, reversing the two 1.0s.
#     Upstream promises nothing there, so the tied `topk` case below compares
#     values only, via `_topk_multiset_check`, and every case that compares
#     indices uses tie-free input. docs/SAMPLING.md §4.
#
# `sorted=False` is the same situation one step further: upstream returns a
# partition artefact (`k=3` of an 8-element tensor gives `[7,6,0]` where
# `sorted=True` gives `[6,7,0]`), so those cases are multiset-compared too.

_ORDER_DTYPES = ["float64", "float32", "float16", "bfloat16", "int64", "int32", "uint8"]

_TIED = [3.0, 1.0, 3.0, 1.0, 2.0, 3.0]
_DISTINCT = [5.0, 1.0, 4.0, 2.0, 3.0, 0.0]


def _topk_multiset_check(t_res, c_res) -> tuple[bool, str]:
    """dtype and shape exactly; values as a sorted multiset; indices only
    through the (value, index) pairing.

    For the cases where upstream's own order is an artefact of its partition
    rather than a promise -- ties, and `sorted=False`. Pinning the order there
    would be pinning an implementation detail; dropping the check entirely
    would let a shim return the wrong *elements*. This checks the elements.
    """
    try:
        t_values, t_indices = t_res[0], t_res[1]
        c_values, c_indices = c_res[0], c_res[1]
    except (TypeError, IndexError, KeyError) as e:
        return False, f"expected a 2-element (values, indices) result on both sides: {e!r}"
    t_dtype, c_dtype = dt.dtype_name(t_values.dtype), dt.dtype_name(c_values.dtype)
    if t_dtype != c_dtype:
        return False, f"values dtype mismatch: torch={t_dtype} c={c_dtype}"
    t_shape = tuple(int(x) for x in t_values.shape)
    c_shape = tuple(int(x) for x in c_values.shape)
    if t_shape != c_shape:
        return False, f"values shape mismatch: torch={t_shape} c={c_shape}"
    # The indices' shape and dtype, both of which the multiset below is blind
    # to: it flattens, so a reshaped index tensor survives it, and it compares
    # values, so an `int32` index survives it. The *order* is what this
    # comparator deliberately does not check -- the shape and the dtype are
    # promises, not partition artefacts. `--self-test` reported both as
    # `_topk_multiset_check + shape-last` / `+ dtype-last` (docs/HARNESS.md §6).
    t_idx_shape = tuple(int(x) for x in t_indices.shape)
    c_idx_shape = tuple(int(x) for x in c_indices.shape)
    if t_idx_shape != c_idx_shape:
        return False, f"indices shape mismatch: torch={t_idx_shape} c={c_idx_shape}"
    t_idx_dtype, c_idx_dtype = dt.dtype_name(t_indices.dtype), dt.dtype_name(c_indices.dtype)
    if t_idx_dtype != c_idx_dtype:
        return False, f"indices dtype mismatch: torch={t_idx_dtype} c={c_idx_dtype}"
    t_pairs = sorted(zip(_flatten_values(t_values.tolist()), _flatten_values(t_indices.tolist())))
    c_pairs = sorted(zip(_flatten_values(c_values.tolist()), _flatten_values(c_indices.tolist())))
    if t_pairs != c_pairs:
        return False, f"selected elements differ: torch={t_pairs!r} c={c_pairs!r}"
    return True, (
        f"values dtype={t_dtype} shape={t_shape}, same {len(t_pairs)} (value, index) pairs "
        f"(indices dtype={t_idx_dtype} shape={t_idx_shape}) "
        "-- order deliberately unchecked, see the note above"
    )


def sort_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.sort.default"
    cases: list[Case] = []
    for dtype_name in _ORDER_DTYPES:
        for descending in (False, True):
            cases.append(
                Case(
                    name=f"sort(dtype={dtype_name}, descending={descending}) [ties at 3.0 and 1.0]",
                    op=op,
                    run_torch=lambda dtype_name=dtype_name, d=descending: torch_call(
                        _pair(torch_module, c_module, _TIED, (6,), dtype_name)[0], -1, d
                    ),
                    run_c=lambda dtype_name=dtype_name, d=descending: c_module._aten_dispatch(
                        op, _pair(torch_module, c_module, _TIED, (6,), dtype_name)[1], -1, d
                    ),
                    value_check=_pair_result_check,
                    note="ties compared exactly -- upstream's CPU sort is stable in both directions",
                )
            )
    for dim in (0, 1, -1):
        cases.append(
            Case(
                name=f"sort(float32, (2,3), dim={dim})",
                op=op,
                run_torch=lambda dim=dim: torch_call(
                    _pair(torch_module, c_module, [3, 1, 3, 2, 2, 1], (2, 3), "float32")[0], dim, False
                ),
                run_c=lambda dim=dim: c_module._aten_dispatch(
                    op, _pair(torch_module, c_module, [3, 1, 3, 2, 2, 1], (2, 3), "float32")[1], dim, False
                ),
                value_check=_pair_result_check,
                note="lane extraction along a non-last dim",
            )
        )
    nan_flat = [1.0, float("nan"), 0.0, float("inf"), float("-inf")]
    for descending in (False, True):
        cases.append(
            Case(
                name=f"sort(float32, NaN/inf, descending={descending})",
                op=op,
                run_torch=lambda d=descending: torch_call(
                    _pair(torch_module, c_module, nan_flat, (5,), "float32")[0], -1, d
                ),
                run_c=lambda d=descending: c_module._aten_dispatch(
                    op, _pair(torch_module, c_module, nan_flat, (5,), "float32")[1], -1, d
                ),
                value_check=_pair_result_check,
                note=(
                    "torch orders NaN as GREATEST -- last ascending, first descending. "
                    "IEEE says every comparison against it is false, so this is a choice "
                    "torch made and a shim has to copy rather than inherit."
                ),
            )
        )
    cases.append(
        Case(
            name="sort(float32, 80 elements all tied two ways, descending) [stability at scale]",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [1.0] * 40 + [0.0] * 40, (80,), "float32")[0], -1, True
            ),
            run_c=lambda: c_module._aten_dispatch(
                op, _pair(torch_module, c_module, [1.0] * 40 + [0.0] * 40, (80,), "float32")[1], -1, True
            ),
            value_check=_pair_result_check,
            note="indices must come back as 0..79 -- an unstable sort would pass a value check and fail this",
        )
    )
    for flat, shape, note in [([5.0], (), "0-d: value and index both 0-d"), ([], (0,), "empty")]:
        cases.append(
            Case(
                name=f"sort(float32, {note})",
                op=op,
                run_torch=lambda flat=flat, shape=shape: torch_call(
                    _pair(torch_module, c_module, flat, shape, "float32")[0], -1, False
                ),
                run_c=lambda flat=flat, shape=shape: c_module._aten_dispatch(
                    op, _pair(torch_module, c_module, flat, shape, "float32")[1], -1, False
                ),
                value_check=_pair_result_check,
                note=note,
            )
        )
    cases.append(
        Case(
            name="sort(dim out of range rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, _TIED, (6,), "float32")[0], 3, False
            ),
            run_c=lambda: c_module._aten_dispatch(
                op, _pair(torch_module, c_module, _TIED, (6,), "float32")[1], 3, False
            ),
            expect="both_error",
            note="IndexError on both sides",
        )
    )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # self/dim/descending all by keyword.
    kw_t, kw_c = _pair(torch_module, c_module, _TIED, (6,), "float32")
    cases.append(
        Case(
            name="sort(self=/dim=/descending= all by keyword)",
            op=op,
            run_torch=lambda: torch_call(self=kw_t, dim=-1, descending=True),
            run_c=lambda: c_module._aten_dispatch(op, self=kw_c, dim=-1, descending=True),
            value_check=_pair_result_check,
        )
    )
    return cases


def topk_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.topk.default"
    cases: list[Case] = []
    for dtype_name in _ORDER_DTYPES:
        for k in (1, 3, 6):
            for largest in (True, False):
                cases.append(
                    Case(
                        name=f"topk(dtype={dtype_name}, k={k}, largest={largest}) [distinct values]",
                        op=op,
                        run_torch=lambda dtype_name=dtype_name, k=k, lg=largest: torch_call(
                            _pair(torch_module, c_module, _DISTINCT, (6,), dtype_name)[0], k, -1, lg, True
                        ),
                        run_c=lambda dtype_name=dtype_name, k=k, lg=largest: c_module._aten_dispatch(
                            op, _pair(torch_module, c_module, _DISTINCT, (6,), dtype_name)[1], k, -1, lg, True
                        ),
                        value_check=_pair_result_check,
                        note="no ties, so the indices are determined and compared exactly",
                    )
                )
    cases.append(
        Case(
            name="topk(float32, k=3, largest=True) [ties -- values and selection only]",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, _TIED, (6,), "float32")[0], 3, -1, True, True
            ),
            run_c=lambda: c_module._aten_dispatch(
                op, _pair(torch_module, c_module, _TIED, (6,), "float32")[1], 3, -1, True, True
            ),
            value_check=_topk_multiset_check,
            note="upstream's tie order here is a partition artefact -- see the note above",
        )
    )
    cases.append(
        Case(
            name="topk(float32, k=6, largest=True) [ties, k == n -- upstream reverses the tied pair]",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, _TIED, (6,), "float32")[0], 6, -1, True, True
            ),
            run_c=lambda: c_module._aten_dispatch(
                op, _pair(torch_module, c_module, _TIED, (6,), "float32")[1], 6, -1, True, True
            ),
            value_check=_topk_multiset_check,
            note=(
                "MEASURED DIVERGENCE, deliberately not chased: upstream answers indices "
                "[0,2,5,4,3,1] and this shim answers [0,2,5,4,1,3]. Same six elements, "
                "different order among equal values. torch.topk documents no order for "
                "ties; the values -- which is all TopKLogitsWarper reads -- are identical."
            ),
        )
    )
    for k in (1, 3):
        cases.append(
            Case(
                name=f"topk(float32, k={k}, sorted=False) [order unspecified upstream]",
                op=op,
                run_torch=lambda k=k: torch_call(
                    _pair(torch_module, c_module, [5.0, 1.0, 4.0, 2.0, 3.0, 0.0, 9.0, 7.0], (8,), "float32")[0],
                    k, -1, True, False,
                ),
                run_c=lambda k=k: c_module._aten_dispatch(
                    op,
                    _pair(torch_module, c_module, [5.0, 1.0, 4.0, 2.0, 3.0, 0.0, 9.0, 7.0], (8,), "float32")[1],
                    k, -1, True, False,
                ),
                value_check=_topk_multiset_check,
                note=(
                    "sorted=False licenses any order and upstream uses it: k=3 answers "
                    "[7,6,0] where sorted=True answers [6,7,0]. This shim always sorts, "
                    "which is within the licence."
                ),
            )
        )
    cases.append(
        Case(
            name="topk(float32, (2,3), k=2, dim=0)",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [3, 1, 3, 2, 2, 1], (2, 3), "float32")[0], 2, 0, True, True
            ),
            run_c=lambda: c_module._aten_dispatch(
                op, _pair(torch_module, c_module, [3, 1, 3, 2, 2, 1], (2, 3), "float32")[1], 2, 0, True, True
            ),
            value_check=_pair_result_check,
            note="selection along a non-last dim; no ties within a lane",
        )
    )
    cases.append(
        Case(
            name="topk(float32, 0-d, k=1)",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [5.0], (), "float32")[0], 1, -1, True, True
            ),
            run_c=lambda: c_module._aten_dispatch(
                op, _pair(torch_module, c_module, [5.0], (), "float32")[1], 1, -1, True, True
            ),
            value_check=_pair_result_check,
            note="torch answers a 0-d value and a 0-d index of 0 rather than refusing",
        )
    )
    cases.append(
        Case(
            name="topk(float32, k=0)",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, _DISTINCT, (6,), "float32")[0], 0, -1, True, True
            ),
            run_c=lambda: c_module._aten_dispatch(
                op, _pair(torch_module, c_module, _DISTINCT, (6,), "float32")[1], 0, -1, True, True
            ),
            value_check=_pair_result_check,
            note="k=0 is legal and gives empty results, unlike k<0",
        )
    )
    for k, why in [(7, "k > n"), (-1, "k < 0 -- torch gives the same 'out of range' message")]:
        cases.append(
            Case(
                name=f"topk(k={k} rejected on both sides) [{why}]",
                op=op,
                run_torch=lambda k=k: torch_call(
                    _pair(torch_module, c_module, _DISTINCT, (6,), "float32")[0], k, -1, True, True
                ),
                run_c=lambda k=k: c_module._aten_dispatch(
                    op, _pair(torch_module, c_module, _DISTINCT, (6,), "float32")[1], k, -1, True, True
                ),
                expect="both_error",
                note="torch: RuntimeError 'selected index k out of range'",
            )
        )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # self/k/dim/largest/sorted all by keyword.
    kw_t, kw_c = _pair(torch_module, c_module, _DISTINCT, (6,), "float32")
    cases.append(
        Case(
            name="topk(self=/k=/dim=/largest=/sorted= all by keyword)",
            op=op,
            run_torch=lambda: torch_call(self=kw_t, k=2, dim=-1, largest=True, sorted=True),
            run_c=lambda: c_module._aten_dispatch(op, self=kw_c, k=2, dim=-1, largest=True, sorted=True),
            value_check=_pair_result_check,
        )
    )
    return cases


# --- aten.scatter.src --------------------------------------------------------
#
# Written against torch's shape rule, which is looser than candle's: torch asks
# only that `index` be **no larger** than `self` (off the scatter axis) and than
# `src`, while candle demands equality. The generation loop uses exactly the
# shape candle rejects -- a `(batch, k)` index scattered into a `(batch, vocab)`
# row -- so the two `index smaller than src/self` cases below are the ones that
# would break if someone "simplified" this onto `Tensor::scatter`.


def scatter_src_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.scatter.src"
    cases: list[Case] = []

    def case(name, self_arg, dim, idx_arg, src_arg, note, expect="match"):
        cases.append(
            Case(
                name=name,
                op=op,
                run_torch=lambda: torch_call(
                    _pair(torch_module, c_module, *self_arg)[0],
                    dim,
                    _pair(torch_module, c_module, *idx_arg)[0],
                    _pair(torch_module, c_module, *src_arg)[0],
                ),
                run_c=lambda: c_module._aten_dispatch(
                    op,
                    _pair(torch_module, c_module, *self_arg)[1],
                    dim,
                    _pair(torch_module, c_module, *idx_arg)[1],
                    _pair(torch_module, c_module, *src_arg)[1],
                ),
                expect=expect,
                note=note,
            )
        )

    src_35 = (list(range(1, 16)), (3, 5), "float32")
    zeros_35 = ([0.0] * 15, (3, 5), "float32")
    for dtype_name in ["float64", "float32", "float16", "bfloat16", "int64", "int32"]:
        case(
            f"scatter(dtype={dtype_name}, dim=1, index (3,3) into self (3,5))",
            ([0] * 15, (3, 5), dtype_name),
            1,
            ([0, 1, 2] * 3, (3, 3), "int64"),
            (list(range(1, 16)), (3, 5), dtype_name),
            "index smaller than both self and src along the scatter axis -- the shape "
            "candle's own scatter refuses",
        )
    case(
        "scatter(float32, dim=0, index (1,5) into self (3,5))",
        zeros_35, 0, ([0, 1, 2, 0, 0], (1, 5), "int64"), src_35,
        "index smaller than self along a non-scatter axis",
    )
    case(
        "scatter(float32, duplicate indices -- last write wins)",
        ([0.0] * 5, (1, 5), "float32"), 1, ([0, 0, 0], (1, 3), "int64"), ([1.0, 2.0, 3.0, 0.0, 0.0], (1, 5), "float32"),
        "three writes to column 0; torch leaves the last (3.0), measured",
    )
    case(
        "scatter(float32, 1-D)",
        ([0.0] * 5, (5,), "float32"), 0, ([4, 0], (2,), "int64"), ([9.0, 8.0], (2,), "float32"),
        "rank 1 -- the scatter axis is the only axis",
    )
    case(
        "scatter(float32, int32 index accepted)",
        ([0.0] * 3, (3,), "float32"), 0, ([1], (1,), "int32"), ([1.0], (1,), "float32"),
        "torch accepts int32 here -- unlike masked_fill's mask, which must be exactly bool",
    )
    case(
        "scatter(float32, index out of bounds rejected on both sides)",
        ([0.0] * 3, (3,), "float32"), 0, ([5], (1,), "int64"), ([1.0], (1,), "float32"),
        "torch: 'index 5 is out of bounds for dimension 0 with size 3'",
        expect="both_error",
    )
    case(
        "scatter(float32, negative index rejected on both sides)",
        ([0.0] * 3, (3,), "float32"), 0, ([-1], (1,), "int64"), ([1.0], (1,), "float32"),
        "unlike a dim, a scatter index is not wrapped -- torch refuses -1",
        expect="both_error",
    )
    case(
        "scatter(self/src dtype mismatch rejected on both sides)",
        ([0.0] * 3, (3,), "float32"), 0, ([1], (1,), "int64"), ([1], (1,), "int64"),
        "torch: 'scatter(): Expected self.dtype to be equal to src.dtype' -- no promotion",
        expect="both_error",
    )
    case(
        "scatter(index rank mismatch rejected on both sides)",
        zeros_35, 1, ([0, 1, 2], (3,), "int64"), src_35,
        "torch: 'Index tensor must have the same number of dimensions as self tensor'",
        expect="both_error",
    )
    case(
        "scatter(index larger than src rejected on both sides)",
        zeros_35, 1, ([0, 1, 2], (1, 3), "int64"), ([1.0, 2.0], (1, 2), "float32"),
        "'no larger than self ... and no larger size than src' -- this violates the src half",
        expect="both_error",
    )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # self/dim/index/src all by keyword.
    kw_self_t, kw_self_c = _pair(torch_module, c_module, *zeros_35)
    kw_idx_t, kw_idx_c = _pair(torch_module, c_module, [0, 1, 2] * 3, (3, 3), "int64")
    kw_src_t, kw_src_c = _pair(torch_module, c_module, *src_35)
    cases.append(
        Case(
            name="scatter(self=/dim=/index=/src= all by keyword)",
            op=op,
            run_torch=lambda: torch_call(self=kw_self_t, dim=1, index=kw_idx_t, src=kw_src_t),
            run_c=lambda: c_module._aten_dispatch(op, self=kw_self_c, dim=1, index=kw_idx_c, src=kw_src_c),
        )
    )
    return cases


# --- aten.fill_.Tensor -------------------------------------------------------
#
# `fill_` with a 0-d tensor rather than a Python number. It was implemented
# alongside `fill_.Scalar` and parked in `IMPLEMENTED_AWAITING_GOLDEN` for want
# of exactly this builder; these cases are what moved it across.
#
# The difference from `fill_.Scalar` is not cosmetic: the `c10::checked_convert`
# overflow refusal that `fill_.Scalar` reproduces does **not** apply to a tensor
# value. `fill_(float16_tensor, tensor(1e6))` gives `inf` on upstream too
# (measured), where `fill_(float16_tensor, 1e6)` raises. So the float16 case
# below is the mirror image of `full_cases`' live regression trap, and it is
# `expect="match"` for the opposite reason: here `inf` is the right answer.


def fill__tensor_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.fill_.Tensor"
    cases: list[Case] = []
    for dtype_name in dt.DEFAULT_DTYPES:
        cases.append(
            Case(
                name=f"fill_.Tensor(dtype={dtype_name}, 0-d value of the same dtype)",
                op=op,
                run_torch=lambda dtype_name=dtype_name: torch_call(
                    _pair(torch_module, c_module, [0, 0, 0, 0], (2, 2), dtype_name)[0],
                    _pair(torch_module, c_module, [3], (), dtype_name)[0],
                ),
                run_c=lambda dtype_name=dtype_name: c_module._aten_dispatch(
                    op,
                    _pair(torch_module, c_module, [0, 0, 0, 0], (2, 2), dtype_name)[1],
                    _pair(torch_module, c_module, [3], (), dtype_name)[1],
                ),
                note="in-place: compares the mutated operand fill_ returns",
            )
        )
    cases.append(
        Case(
            name="fill_.Tensor(int64 <- 0-d float32 2.7) [the value is cast to self's dtype, truncating]",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [0, 0], (2,), "int64")[0],
                _pair(torch_module, c_module, [2.7], (), "float32")[0],
            ),
            run_c=lambda: c_module._aten_dispatch(
                op,
                _pair(torch_module, c_module, [0, 0], (2,), "int64")[1],
                _pair(torch_module, c_module, [2.7], (), "float32")[1],
            ),
            note="self keeps its dtype; the value does not widen it",
        )
    )
    cases.append(
        Case(
            name="fill_.Tensor(float16 <- 0-d 1e6) [overflows to inf on BOTH sides, unlike fill_.Scalar]",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [0.0] * 3, (3,), "float16")[0],
                _pair(torch_module, c_module, [1e6], (), "float32")[0],
            ),
            run_c=lambda: c_module._aten_dispatch(
                op,
                _pair(torch_module, c_module, [0.0] * 3, (3,), "float16")[1],
                _pair(torch_module, c_module, [1e6], (), "float32")[1],
            ),
            note=(
                "the mirror of full_cases' float16 trap: c10::checked_convert guards the "
                "*Scalar* overload, not this one, so inf is upstream's own answer here"
            ),
        )
    )
    cases.append(
        Case(
            name="fill_.Tensor(1-D value rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [0.0] * 3, (3,), "float32")[0],
                _pair(torch_module, c_module, [1.0], (1,), "float32")[0],
            ),
            run_c=lambda: c_module._aten_dispatch(
                op,
                _pair(torch_module, c_module, [0.0] * 3, (3,), "float32")[1],
                _pair(torch_module, c_module, [1.0], (1,), "float32")[1],
            ),
            expect="both_error",
            note=(
                "torch: 'fill_ only supports 0-dimension value tensor but got tensor with "
                "1 dimensions.' The shim raises TypeError rather than RuntimeError; "
                "both_error accepts either, and the refusal is the point."
            ),
        )
    )
    cases.extend(
        c for c in _setitem_member_cases(torch_module, c_module)
        if c.op == "aten.fill_.Tensor"
    )
    cases.extend(
        c for c in _view_write_cases(torch_module, c_module)
        if c.op == "aten.fill_.Tensor"
    )
    return cases


# --- aten.multinomial.default ------------------------------------------------
#
# The only op in this file that draws, and therefore the only one whose cases
# have to say *when* each side draws. Both sides are seeded inside the
# `run_torch`/`run_c` lambdas -- `torch.manual_seed(s)` and
# `_C._shim_manual_seed(s)` -- so each case starts both generators at the same
# point in the same stream and the sampled indices can be compared **exactly**.
#
# That is only meaningful because docs/RNG.md's port makes the two streams the
# same object. The module note above still says a seed cannot synchronise two
# independent RNGs; it is right about *independent* ones and no longer
# describes this codebase (see the uniform_/normal_ builders, which were
# promoted off `_range_check` for the same reason).
#
# The cases have to cross the branch that decides which algorithm runs, because
# the branch is not where the argument names suggest: upstream takes the
# Gumbel-style fast path when `!replacement` **or `num_samples == 1`**, so
# `multinomial(probs, 1)` -- the call `GenerationMixin._sample` makes -- takes
# it even with `replacement` left False. `num_samples=3, replacement=True` is
# the only combination below that reaches the cumulative-sum kernel.

_MULTINOMIAL_DTYPES = ["float64", "float32", "float16", "bfloat16"]
_MULTINOMIAL_SEEDS = [0, 1, 42, 1234]


def _seeded_multinomial(torch_module, c_module, torch_call, op, flat, shape, dtype_name, n_sample, replacement, seed):
    def run_torch():
        torch_module.manual_seed(seed)
        return torch_call(
            _pair(torch_module, c_module, flat, shape, dtype_name)[0], n_sample, replacement
        )

    def run_c():
        c_module._shim_manual_seed(seed)
        return c_module._aten_dispatch(
            op, _pair(torch_module, c_module, flat, shape, dtype_name)[1], n_sample, replacement
        )

    return run_torch, run_c


def multinomial_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.multinomial.default"
    cases: list[Case] = []
    # Deliberately unnormalised and deliberately not uniform: upstream
    # normalises by the row sum itself, and a uniform row would hide any
    # ordering mistake.
    row = [(i % 7) + 1 for i in range(11)]
    grid = [
        (row, (11,), 1, False, "1-D, one sample -- the fast path, and the call the sampler makes"),
        (row, (11,), 1, True, "replacement=True with one sample still takes the FAST path"),
        (row, (11,), 3, False, "no replacement, three samples -- fast path via topk"),
        (row, (11,), 3, True, "the cumulative-sum kernel, the only combination that reaches it"),
        (row * 3, (3, 11), 1, False, "2-D: one sample per row"),
        (row * 3, (3, 11), 5, True, "2-D cumulative-sum kernel, five samples per row"),
    ]
    for dtype_name in _MULTINOMIAL_DTYPES:
        for flat, shape, n_sample, replacement, note in grid:
            for seed in _MULTINOMIAL_SEEDS:
                run_torch, run_c = _seeded_multinomial(
                    torch_module, c_module, torch_call, op, flat, shape, dtype_name,
                    n_sample, replacement, seed,
                )
                cases.append(
                    Case(
                        name=(
                            f"multinomial(dtype={dtype_name}, shape={shape}, num_samples={n_sample}, "
                            f"replacement={replacement}, seed={seed})"
                        ),
                        op=op,
                        run_torch=run_torch,
                        run_c=run_c,
                        note=note + " -- both generators seeded to the same value; indices compared exactly",
                    )
                )

    def refusal(name, flat, shape, dtype_name, n_sample, replacement, note):
        cases.append(
            Case(
                name=name,
                op=op,
                run_torch=lambda: torch_call(
                    _pair(torch_module, c_module, flat, shape, dtype_name)[0], n_sample, replacement
                ),
                run_c=lambda: c_module._aten_dispatch(
                    op, _pair(torch_module, c_module, flat, shape, dtype_name)[1], n_sample, replacement
                ),
                expect="both_error",
                note=note,
            )
        )

    refusal("multinomial(num_samples=0 rejected on both sides)", row, (11,), "float32", 0, False,
            "torch: 'cannot sample n_sample <= 0 samples'")
    refusal("multinomial(num_samples > categories without replacement rejected on both sides)",
            row, (11,), "float32", 12, False,
            "torch: 'cannot sample n_sample > prob_dist.size(-1) samples without replacement'")
    refusal("multinomial(int64 input rejected on both sides)", [1, 2, 3], (3,), "int64", 1, False,
            "torch: 'multinomial only supports floating-point dtypes for input, got: Long'")
    refusal("multinomial(3-D input rejected on both sides)", [1.0] * 8, (2, 2, 2), "float32", 1, False,
            "torch: 'prob_dist must be 1 or 2 dim'")
    refusal("multinomial(negative probability rejected on both sides)", [-1.0, 2.0], (2,), "float32", 1, False,
            "torch: 'probability tensor contains either `inf`, `nan` or element < 0'")
    refusal("multinomial(inf probability rejected on both sides)", [float("inf"), 2.0], (2,), "float32", 1, False,
            "same check -- max() < INFINITY is false")
    refusal("multinomial(NaN probability rejected on both sides)", [float("nan"), 2.0], (2,), "float32", 1, False,
            "same check -- every comparison against NaN is false, so both halves of it fail")
    refusal("multinomial(all-zero row rejected on both sides)", [0.0, 0.0], (2,), "float32", 1, False,
            "torch: 'invalid multinomial distribution (sum of probabilities <= 0)'")
    refusal("multinomial(all-zero row, with replacement, rejected on both sides)", [0.0, 0.0], (2,), "float32", 2, True,
            "the same refusal from the other kernel -- reached by a different check upstream")

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # self/num_samples/replacement all by keyword. Seeded like
    # `_seeded_multinomial` above so the drawn indices compare exactly
    # rather than only dtype/shape.
    kw_t, kw_c = _pair(torch_module, c_module, row, (11,), "float32")

    def _kw_multinomial_run_torch():
        torch_module.manual_seed(0)
        return torch_call(self=kw_t, num_samples=1, replacement=False)

    def _kw_multinomial_run_c():
        c_module._shim_manual_seed(0)
        return c_module._aten_dispatch(op, self=kw_c, num_samples=1, replacement=False)

    cases.append(
        Case(
            name="multinomial(self=/num_samples=/replacement= all by keyword)",
            op=op,
            run_torch=_kw_multinomial_run_torch,
            run_c=_kw_multinomial_run_c,
            note="both generators seeded to the same value; index compared exactly",
        )
    )
    return cases


# --- the four ops docs/GPT2.md measured a 2-layer GPT-2 stopping on ----------
#
# Re-measured against `_aten_implemented()` at 78 ops, not docs/GAP.md's 60-op
# snapshot: a GPT-2 that Llama-shaped work had already unblocked still stops on
# `addmm`, `native_layer_norm`, `split.Tensor` and `tanh`, and on nothing else.


_TANH_DTYPES = ["float64", "float32", "float16", "bfloat16"]
# The promoting inputs. `uint8` is here with *non-negative* values only: a
# negative literal is where `_C._tensor_from_flat` and `torch.tensor` disagree
# (torch wraps -1 to 255, `_tensor_from_flat` saturates to 0), which is a
# constructor difference and would make this op's cases fail for a reason that
# has nothing to do with `tanh`. See docs/GPT2.md.
_TANH_PROMOTING_DTYPES = ["int64", "int32", "int16", "uint8"]


def tanh_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.tanh.default"
    cases: list[Case] = []
    scenarios = [
        ([0.0, 1.0, -1.0, 2.0], (2, 2), "assorted"),
        # tanh saturates: torch answers exactly +-1.0 well before the input
        # overflows, and a shim that computed exp() naively would give NaN.
        ([-100.0, 100.0, 20.0, -20.0], (2, 2), "saturation -- torch gives exactly +-1.0"),
        ([0.0], (), "0-d"),
        ([float("nan"), float("inf"), float("-inf")], (3,), "NaN/+-inf -- nan, 1.0, -1.0"),
    ]
    for dtype_name in _TANH_DTYPES:
        for flat, shape, note in scenarios:
            cases.append(_unary_case(torch_module, c_module, op, torch_call, dtype_name, flat, shape, note))
    # The promotion rule, which is `cos`/`sin`'s and not `silu`'s: an integral
    # input gives float32 rather than raising.
    for dtype_name in _TANH_PROMOTING_DTYPES:
        cases.append(
            _unary_case(
                torch_module, c_module, op, torch_call, dtype_name, [0, 1, 2, 3], (2, 2),
                "integral input promotes to the default float",
            )
        )
    return cases


# --- aten.addmm.default ------------------------------------------------------
# The dtype split is `mm`'s, for `mm`'s reason: the multiply is candle's
# `matmul`, which has no integral or bfloat16 kernel.


def _addmm_case(
    torch_module, c_module, torch_call, dtype_name,
    self_flat, self_shape, m1_flat, m1_shape, m2_flat, m2_shape,
    kwargs=None, expect="match", note="",
) -> Case:
    kwargs = kwargs or {}
    op = "aten.addmm.default"
    s_t, s_c = pair_from_flat(torch_module, c_module, self_flat, self_shape, dtype_name)
    a_t, a_c = pair_from_flat(torch_module, c_module, m1_flat, m1_shape, dtype_name)
    b_t, b_c = pair_from_flat(torch_module, c_module, m2_flat, m2_shape, dtype_name)
    return Case(
        name=f"addmm(dtype={dtype_name}, self={self_shape}, {m1_shape}x{m2_shape}, {kwargs}) [{note}]",
        op=op,
        run_torch=lambda: torch_call(s_t, a_t, b_t, **kwargs),
        run_c=lambda: c_module._aten_dispatch(op, s_c, a_c, b_c, **kwargs),
        expect=expect,
        note=note,
    )


def _addmm_t_case(
    torch_module, c_module, torch_call, dtype_name,
    self_flat, self_shape, m1_flat, m1_shape, w_flat, w_shape, note="",
) -> Case:
    """`mat2` fed in as `t(weight)` -- `bootstrap.py::linear`'s bias branch is
    literally `dispatch("aten.addmm.default", bias, input, _t(weight))`
    (docs/LINEAR.md §1), and `addmm_default` reaches the same
    `gemm_with_layout_fallback` `matmul_default` does, so this is the same
    fix exercised through the other kernel it landed in. `w_shape` names the
    shape *before* the transpose."""
    op = "aten.addmm.default"
    s_t, s_c = pair_from_flat(torch_module, c_module, self_flat, self_shape, dtype_name)
    a_t, a_c = pair_from_flat(torch_module, c_module, m1_flat, m1_shape, dtype_name)
    wbase_t, wbase_c = pair_from_flat(torch_module, c_module, w_flat, w_shape, dtype_name)
    w_t = wbase_t.t()
    w_c = c_module._aten_dispatch("aten.t.default", wbase_c)
    out_w_shape = (w_shape[1], w_shape[0])
    return Case(
        name=f"addmm(dtype={dtype_name}, self={self_shape}, {m1_shape}x{w_shape} transposed view -> {out_w_shape}) [{note}]",
        op=op,
        run_torch=lambda: torch_call(s_t, a_t, w_t),
        run_c=lambda: c_module._aten_dispatch(op, s_c, a_c, w_c),
        note=note,
    )


def _addmm_t_model_case(torch_module, c_module, torch_call, dtype_name, m, k, n, note) -> Case:
    """Model-scale sibling of `_addmm_t_case`, checked against the
    scale-aware GEMM bound (`_gemm_scale_check`) the way `_big_gemm_case`'s
    other rows are -- this is `nn.Linear(bias=True)` at a real depth, with
    `mat2` the transposed weight view it actually receives."""
    op = "aten.addmm.default"
    a_flat = _gemm_lcg(m * k, 201)
    w_flat = _gemm_lcg(n * k, 202)  # base shape (n, k), transposed -> (k, n)
    bias_flat = _gemm_lcg(n, 203)
    a_t, a_c = pair_from_flat(torch_module, c_module, a_flat, (m, k), dtype_name)
    wbase_t, wbase_c = pair_from_flat(torch_module, c_module, w_flat, (n, k), dtype_name)
    w_t = wbase_t.t()
    w_c = c_module._aten_dispatch("aten.t.default", wbase_c)
    bias_t, bias_c = pair_from_flat(torch_module, c_module, bias_flat, (n,), dtype_name)
    return Case(
        name=f"addmm(dtype={dtype_name}, self=({n},), ({m},{k})x({n},{k}) transposed view -> ({k},{n})) [model-scale, k={k}: {note}]",
        op=op,
        run_torch=lambda: torch_call(bias_t, a_t, w_t),
        run_c=lambda: c_module._aten_dispatch(op, bias_c, a_c, w_c),
        note=note,
        value_check=_gemm_scale_check(dtype_name, k),
    )


# (3x2) @ (2x3) -> (3x3); the product is [[1,2,8],[3,4,18],[5,6,28]].
_ADDMM_M1 = ([1.0, 2.0, 3.0, 4.0, 5.0, 6.0], (3, 2))
_ADDMM_M2 = ([1.0, 0.0, 2.0, 0.0, 1.0, 3.0], (2, 3))
_ADDMM_SELF = ([1.0, 1.0, 1.0, 2.0, 2.0, 2.0, 3.0, 3.0, 3.0], (3, 3))
# transpose(_ADDMM_W_BASE) == _ADDMM_M2 exactly (content, not just shape):
# [[1,0],[0,1],[2,3]].t() == [[1,0,2],[0,1,3]] -- so the transposed-view
# cases below are hand-checkable against the same known 3x3 answer the plain
# "self + mat1 @ mat2" scenario above already pins.
_ADDMM_W_BASE = ([1.0, 0.0, 0.0, 1.0, 2.0, 3.0], (3, 2))


def addmm_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.addmm.default"
    cases: list[Case] = []

    scenarios = [
        (None, "plain: self + mat1 @ mat2"),
        (dict(beta=2, alpha=3), "integer beta/alpha"),
        (dict(beta=0.5, alpha=0.25), "fractional beta/alpha"),
        # The two quick returns. Upstream skips the branch rather than
        # multiplying by zero, which is only visible with a non-finite operand
        # -- covered separately below.
        (dict(beta=0), "beta=0 -- self dropped"),
        (dict(alpha=0), "alpha=0 -- product dropped"),
        (dict(beta=0, alpha=0), "both zero -- a shaped tensor of zeros, not an error"),
        (dict(beta=True), "beta as a bool, which torch reads as 1"),
        (dict(beta=False), "beta as a bool, which torch reads as 0"),
    ]
    for dtype_name in _MM_MATCH_DTYPES:
        for kwargs, note in scenarios:
            cases.append(
                _addmm_case(
                    torch_module, c_module, torch_call, dtype_name,
                    *_ADDMM_SELF, *_ADDMM_M1, *_ADDMM_M2, kwargs=kwargs, note=note,
                )
            )
        # Every shape `self` is allowed to arrive in. The 1-D one is the whole
        # reason this op exists here: `nn.Linear`'s bias is a 1-D row.
        for self_flat, self_shape, note in [
            ([1.0, 2.0, 3.0], (3,), "1-D bias -- nn.Linear's shape"),
            ([7.0], (), "0-d bias"),
            ([1.0, 2.0, 3.0], (3, 1), "column broadcast"),
            ([1.0, 2.0, 3.0], (1, 3), "row broadcast"),
            ([1.0], (1, 1), "(1,1) broadcast"),
        ]:
            cases.append(
                _addmm_case(
                    torch_module, c_module, torch_call, dtype_name,
                    self_flat, self_shape, *_ADDMM_M1, *_ADDMM_M2, note=note,
                )
            )

    # The quick returns, proven rather than asserted: with a non-finite value in
    # the dropped branch, "skip" and "multiply by zero" give different answers.
    inf_m1 = ([float("inf"), 2.0, 3.0, 4.0, 5.0, 6.0], (3, 2))
    nan_self = ([float("nan")] * 9, (3, 3))
    cases.append(
        _addmm_case(
            torch_module, c_module, torch_call, "float32",
            *nan_self, *_ADDMM_M1, *_ADDMM_M2, kwargs=dict(beta=0),
            note="beta=0 with a NaN self -- 0*nan would be nan, torch gives the clean product",
        )
    )
    cases.append(
        _addmm_case(
            torch_module, c_module, torch_call, "float32",
            *_ADDMM_SELF, *inf_m1, *_ADDMM_M2, kwargs=dict(alpha=0),
            note="alpha=0 with an inf in mat1 -- 0*inf would be nan, torch gives the clean self",
        )
    )

    # Empty extents: torch answers, it does not refuse.
    cases.append(
        _addmm_case(
            torch_module, c_module, torch_call, "float32",
            [], (0, 3), [], (0, 2), *_ADDMM_M2, note="zero rows",
        )
    )
    cases.append(
        _addmm_case(
            torch_module, c_module, torch_call, "float32",
            [], (3, 0), *_ADDMM_M1, [], (2, 0), note="zero columns",
        )
    )

    # Refusals. Each one is a sentence torch says; the point is that the shim
    # does not compute where torch declines.
    for self_flat, self_shape, m1, m2, note in [
        ([1.0, 2.0], (2,), _ADDMM_M1, _ADDMM_M2, "self not expandable to the product's shape"),
        ([1.0] * 18, (2, 3, 3), _ADDMM_M1, _ADDMM_M2, "self has more dims than the product"),
        (*_ADDMM_SELF, ([1.0] * 6, (1, 3, 2)), _ADDMM_M2, "mat1 is 3-D -- 'mat1 must be a matrix'"),
        (*_ADDMM_SELF, _ADDMM_M1, ([1.0, 0.0, 2.0], (3,)), "mat2 is 1-D -- 'mat2 must be a matrix'"),
        (*_ADDMM_SELF, _ADDMM_M1, ([1.0] * 9, (3, 3)), "k mismatch -- shapes cannot be multiplied"),
    ]:
        cases.append(
            _addmm_case(
                torch_module, c_module, torch_call, "float32",
                self_flat, self_shape, *m1, *m2, expect="both_error", note=note,
            )
        )
    # `self` is validated even when nothing reads it -- measured with
    # beta=0, alpha=0, where neither operand contributes.
    cases.append(
        _addmm_case(
            torch_module, c_module, torch_call, "float32",
            [1.0, 2.0], (2,), *_ADDMM_M1, *_ADDMM_M2,
            kwargs=dict(beta=0, alpha=0), expect="both_error",
            note="self shape is checked even when both factors are zero",
        )
    )
    # bool has no addmm_impl_cpu_ upstream, and the shim says the same thing.
    cases.append(
        Case(
            name="addmm(dtype=bool) [no addmm_impl_cpu_ for Bool on either side]",
            op=op,
            run_torch=lambda: torch_call(
                torch_module.ones(2, 2, dtype=torch_module.bool),
                torch_module.ones(2, 2, dtype=torch_module.bool),
                torch_module.ones(2, 2, dtype=torch_module.bool),
            ),
            run_c=lambda: c_module._aten_dispatch(
                op,
                c_module._tensor_from_flat([1, 1, 1, 1], [2, 2], dtype=c_module.bool),
                c_module._tensor_from_flat([1, 1, 1, 1], [2, 2], dtype=c_module.bool),
                c_module._tensor_from_flat([1, 1, 1, 1], [2, 2], dtype=c_module.bool),
            ),
            expect="both_error",
            note="torch: '\"addmm_impl_cpu_\" not implemented for Bool'",
        )
    )

    # The inherited gap: candle's matmul has no kernel for these, exactly as
    # `aten.mm.default` already records (docs/TORCH_C.md §2).
    for dtype_name in _MM_C_ERROR_DTYPES:
        cases.append(
            _addmm_case(
                torch_module, c_module, torch_call, dtype_name,
                [1, 1, 1, 1], (2, 2), [1, 2, 3, 4], (2, 2), [1, 0, 0, 1], (2, 2),
                expect="c_error",
                note=f"candle's matmul has no kernel for {dtype_name}; torch's CPU addmm does. "
                     "Same gap aten.mm.default already carries.",
            )
        )
        # ...but with alpha=0 there is no matmul to refuse, and both sides
        # agree. Not a workaround -- it is the quick return, and pinning it
        # keeps the gap above honest about *what* is missing (the multiply,
        # not the op).
        cases.append(
            _addmm_case(
                torch_module, c_module, torch_call, dtype_name,
                [1, 1, 1, 1], (2, 2), [1, 2, 3, 4], (2, 2), [1, 0, 0, 1], (2, 2),
                kwargs=dict(alpha=0),
                note=f"{dtype_name} with alpha=0 -- no matmul happens, so the gap above does not apply",
            )
        )

    # Model-scale, with the bias -- this is `nn.Linear` at a real width, which
    # is the shape docs/GPT2.md §3.3 measured and §7 left uncovered here.
    for dtype_name, m, k, n, note in [
        ("float32", 64, 512, 64, "nn.Linear(512, 64) on a batch of 64"),
        ("float32", 8, 1024, 8, "depth 1024, where mm's agreement with torch ends"),
        ("float16", 8, 512, 8, "float16 at depth 512 -- the accumulation-dtype question"),
    ]:
        cases.append(
            _big_gemm_case(torch_module, c_module, torch_call, "aten.addmm.default",
                           dtype_name, m, k, n, with_bias=True, note=note)
        )

    # `mat2` fed in as `t(weight)` -- the view nn.Linear(bias=True) actually
    # passes (docs/LINEAR.md §1). Dtype-swept and hand-checkable: same
    # numbers as the "plain" scenario above, since transpose(_ADDMM_W_BASE)
    # == _ADDMM_M2.
    for dtype_name in _MM_MATCH_DTYPES:
        cases.append(
            _addmm_t_case(
                torch_module, c_module, torch_call, dtype_name,
                *_ADDMM_SELF, *_ADDMM_M1, *_ADDMM_W_BASE,
                note="mat2 = t(weight) -- the view nn.Linear(bias=True) actually passes",
            )
        )
    # ...and at model scale, alongside the contiguous-mat2 rows above.
    cases.append(
        _addmm_t_model_case(
            torch_module, c_module, torch_call, "float32", 8, 512, 8,
            note="t(weight) view, nn.Linear(512, 8) bias=True at the real shape",
        )
    )
    cases.append(
        _addmm_t_model_case(
            torch_module, c_module, torch_call, "float16", 8, 512, 8,
            note="t(weight) view, float16 accumulation-dtype question",
        )
    )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # self/mat1/mat2/beta/alpha all by keyword.
    kw_s_t, kw_s_c = pair_from_flat(torch_module, c_module, *_ADDMM_SELF, "float32")
    kw_m1_t, kw_m1_c = pair_from_flat(torch_module, c_module, *_ADDMM_M1, "float32")
    kw_m2_t, kw_m2_c = pair_from_flat(torch_module, c_module, *_ADDMM_M2, "float32")
    cases.append(
        Case(
            name="addmm(self=/mat1=/mat2=/beta=/alpha= all by keyword)",
            op="aten.addmm.default",
            run_torch=lambda: torch_call(self=kw_s_t, mat1=kw_m1_t, mat2=kw_m2_t, beta=2, alpha=3),
            run_c=lambda: c_module._aten_dispatch(
                "aten.addmm.default", self=kw_s_c, mat1=kw_m1_c, mat2=kw_m2_c, beta=2, alpha=3
            ),
        )
    )
    return cases


# --- aten.split.Tensor -------------------------------------------------------
# The one op here that answers with a *list*, so the default dtype/shape/value
# pipeline in compare.py cannot read it. `_chunk_list_check` below is the
# equivalent for a sequence of tensors.


def _chunk_list_check(t_res, c_res) -> tuple[bool, str]:
    """For ops returning a list of tensors (`split`): compare the *number* of
    chunks first -- a shim that padded the last chunk instead of shortening it
    would get every element right and the count wrong -- then each chunk's
    dtype, shape and values."""
    try:
        t_list, c_list = list(t_res), list(c_res)
    except TypeError as e:
        return False, f"expected a sequence of tensors on both sides: {e!r}"
    if len(t_list) != len(c_list):
        return False, (
            f"chunk count differs: torch={len(t_list)} c={len(c_list)} "
            f"(torch shapes {[tuple(x.shape) for x in t_list]}, "
            f"c shapes {[tuple(x.shape) for x in c_list]})"
        )
    for i, (t_chunk, c_chunk) in enumerate(zip(t_list, c_list)):
        t_dtype, c_dtype = dt.dtype_name(t_chunk.dtype), dt.dtype_name(c_chunk.dtype)
        if t_dtype != c_dtype:
            return False, f"chunk[{i}] dtype mismatch: torch={t_dtype} c={c_dtype}"
        t_shape = tuple(int(x) for x in t_chunk.shape)
        c_shape = tuple(int(x) for x in c_chunk.shape)
        if t_shape != c_shape:
            return False, f"chunk[{i}] shape mismatch: torch={t_shape} c={c_shape}"
        tol = dt.tolerance_for(t_dtype)
        t_flat = _flatten_values(t_chunk.tolist())
        c_flat = _flatten_values(c_chunk.tolist())
        for j, (x, y) in enumerate(zip(t_flat, c_flat)):
            if isinstance(x, bool) or isinstance(y, bool):
                if x != y:
                    return False, f"chunk[{i}][{j}] mismatch: torch={x!r} c={y!r}"
                continue
            if not math.isclose(float(x), float(y), rel_tol=tol.rtol, abs_tol=tol.atol):
                return False, f"chunk[{i}][{j}] mismatch: torch={x!r} c={y!r}"
    return True, f"{len(t_list)} chunks matched, shapes {[tuple(x.shape) for x in t_list]}"


_SPLIT_DTYPES = ["float32", "float64", "float16", "int64", "int32"]


def _split_case(torch_module, c_module, torch_call, dtype_name, flat, shape, args, expect="match", note="") -> Case:
    op = "aten.split.Tensor"
    a_t, a_c = pair_from_flat(torch_module, c_module, flat, shape, dtype_name)
    return Case(
        name=f"split(dtype={dtype_name}, shape={shape}, args={args}) [{note}]",
        op=op,
        run_torch=lambda: torch_call(a_t, *args),
        run_c=lambda: c_module._aten_dispatch(op, a_c, *args),
        expect=expect,
        value_check=_chunk_list_check if expect == "match" else None,
        note=note + " -- returns a list of tensors, see _chunk_list_check",
    )


def split_cases(torch_module, c_module, torch_call) -> list[Case]:
    cases: list[Case] = []
    ten = list(range(10))
    for dtype_name in _SPLIT_DTYPES:
        for args, note in [
            ((3,), "10 into 3 -- the last chunk is short (3,3,3,1), not padded"),
            ((5,), "10 into 5 -- exact division"),
            ((20,), "split_size larger than the dimension gives one whole chunk"),
            ((1,), "split_size 1 -- ten chunks"),
            ((10,), "split_size equal to the dimension"),
        ]:
            cases.append(_split_case(torch_module, c_module, torch_call, dtype_name, ten, (10,), args, note=note))
    # The GPT-2 shape: one projection of width 3*d split three ways on the last
    # dim. This is the call the whole op is here for.
    qkv = list(range(24))
    cases.append(
        _split_case(
            torch_module, c_module, torch_call, "float32", qkv, (2, 2, 6), (2, 2),
            note="GPT-2's c_attn(x).split(d, dim=2) -- q, k, v",
        )
    )
    cases.append(
        _split_case(
            torch_module, c_module, torch_call, "float32", qkv, (2, 2, 6), (2, -1),
            note="same split, addressed with a negative dim",
        )
    )
    cases.append(
        _split_case(
            torch_module, c_module, torch_call, "float32", list(range(12)), (3, 4), (3, 1),
            note="uneven split on dim 1 -- chunks are (3,3) and (3,1)",
        )
    )
    cases.append(
        _split_case(
            torch_module, c_module, torch_call, "float32", list(range(12)), (3, 4), (2, 0),
            note="split on dim 0",
        )
    )
    # An empty dimension: one empty chunk for any split size, including 0.
    for args, note in [((3,), "empty dim, split_size 3"), ((0,), "empty dim, split_size 0 -- the one place 0 is legal")]:
        cases.append(
            _split_case(torch_module, c_module, torch_call, "float32", [], (0,), args, note=note)
        )
    # Refusals.
    for flat, shape, args, note in [
        (ten, (10,), (0,), "split_size 0 on a non-empty dim"),
        (ten, (10,), (-1,), "negative split_size"),
        (ten, (10,), (1, 2), "dim out of range"),
        ([1.0], (), (1,), "0-d tensor -- 'split expects at least a 1-dimensional tensor'"),
    ]:
        cases.append(
            _split_case(
                torch_module, c_module, torch_call, "float32", flat, shape, args,
                expect="both_error", note=note,
            )
        )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # self/split_size/dim all by keyword.
    kw_t, kw_c = pair_from_flat(torch_module, c_module, ten, (10,), "float32")
    cases.append(
        Case(
            name="split(self=/split_size=/dim= all by keyword)",
            op="aten.split.Tensor",
            run_torch=lambda: torch_call(self=kw_t, split_size=3, dim=0),
            run_c=lambda: c_module._aten_dispatch("aten.split.Tensor", self=kw_c, split_size=3, dim=0),
            value_check=_chunk_list_check,
        )
    )
    # `Tensor.chunk` lowers here (docs/GROUPED_MM.md §6.4). Its cases live
    # with the other member spellings; this is where they join the suite.
    cases.extend(
        c for c in _chunk_member_cases(torch_module, c_module)
        if c.op == "aten.split.Tensor"
    )
    return cases


# --- aten.native_layer_norm.default -----------------------------------------
# Three results, not one: (output, mean, rstd). `_triple_result_check` is
# `_pair_result_check`'s shape for a schema with one more tensor in it -- and
# unlike that one, every member is a float tensor compared within tolerance,
# because none of them is an index.


def _triple_result_check(t_res, c_res) -> tuple[bool, str]:
    try:
        t_parts = (t_res[0], t_res[1], t_res[2])
        c_parts = (c_res[0], c_res[1], c_res[2])
    except (TypeError, IndexError, KeyError) as e:
        return False, f"expected a 3-element (out, mean, rstd) result on both sides: {e!r}"

    for label, t_part, c_part in zip(("out", "mean", "rstd"), t_parts, c_parts):
        t_dtype, c_dtype = dt.dtype_name(t_part.dtype), dt.dtype_name(c_part.dtype)
        if t_dtype != c_dtype:
            return False, f"{label} dtype mismatch: torch={t_dtype} c={c_dtype}"
        t_shape = tuple(int(x) for x in t_part.shape)
        c_shape = tuple(int(x) for x in c_part.shape)
        if t_shape != c_shape:
            return False, f"{label} shape mismatch: torch={t_shape} c={c_shape}"
        tol = dt.tolerance_for(t_dtype)
        t_flat = _flatten_values(t_part.tolist())
        c_flat = _flatten_values(c_part.tolist())
        if len(t_flat) != len(c_flat):
            return False, f"{label} length differs: torch={len(t_flat)} c={len(c_flat)}"
        for i, (x, y) in enumerate(zip(t_flat, c_flat)):
            xf, yf = float(x), float(y)
            # A negative eps is not refused upstream -- it gives NaN, and the
            # two sides agreeing on NaN is the result being checked.
            if math.isnan(xf) or math.isnan(yf):
                if math.isnan(xf) and math.isnan(yf):
                    continue
                return False, f"{label}[{i}] mismatch: torch={x!r} c={y!r} (NaN on one side only)"
            if not math.isclose(xf, yf, rel_tol=tol.rtol, abs_tol=tol.atol):
                return False, f"{label}[{i}] mismatch: torch={x!r} c={y!r}"
    return True, (
        "out/mean/rstd matched; shapes "
        f"{[tuple(int(v) for v in p.shape) for p in t_parts]}"
    )


_LAYER_NORM_DTYPES = ["float64", "float32", "float16", "bfloat16"]
# 24 values that are not a nice round arithmetic progression in the normalised
# dimension, so a wrong reduction axis shows up as a wrong number rather than
# as the same number by symmetry.
_LN_INPUT = [round(i / 7.0, 6) for i in range(24)]
_LN_WEIGHT = [1.0, 2.0, 0.5, -1.0]
_LN_BIAS = [0.1, 0.2, 0.3, 0.4]


def _layer_norm_case(
    torch_module, c_module, torch_call, dtype_name, flat, shape, normalized_shape,
    weight=None, bias=None, eps=1e-5, param_dtype=None, expect="match", note="",
) -> Case:
    op = "aten.native_layer_norm.default"
    param_dtype = param_dtype or dtype_name
    x_t, x_c = pair_from_flat(torch_module, c_module, flat, shape, dtype_name)
    if weight is None:
        w_t = w_c = None
    else:
        w_t, w_c = pair_from_flat(torch_module, c_module, weight, (len(weight),), param_dtype)
    if bias is None:
        b_t = b_c = None
    else:
        b_t, b_c = pair_from_flat(torch_module, c_module, bias, (len(bias),), param_dtype)
    return Case(
        name=(
            f"native_layer_norm(dtype={dtype_name}, shape={shape}, "
            f"normalized_shape={normalized_shape}, weight={weight is not None}, "
            f"bias={bias is not None}, eps={eps}, param_dtype={param_dtype}) [{note}]"
        ),
        op=op,
        run_torch=lambda: torch_call(x_t, normalized_shape, w_t, b_t, eps),
        run_c=lambda: c_module._aten_dispatch(op, x_c, normalized_shape, w_c, b_c, eps),
        expect=expect,
        value_check=_triple_result_check if expect == "match" else None,
        note=note + " -- returns (out, mean, rstd), see _triple_result_check",
    )


def native_layer_norm_cases(torch_module, c_module, torch_call) -> list[Case]:
    cases: list[Case] = []
    for dtype_name in _LAYER_NORM_DTYPES:
        for weight, bias, note in [
            (_LN_WEIGHT, _LN_BIAS, "weight and bias -- nn.LayerNorm's default"),
            (None, None, "elementwise_affine=False"),
            (_LN_WEIGHT, None, "weight only"),
            (None, _LN_BIAS, "bias only"),
        ]:
            cases.append(
                _layer_norm_case(
                    torch_module, c_module, torch_call, dtype_name,
                    _LN_INPUT, (2, 3, 4), [4], weight=weight, bias=bias, note=note,
                )
            )
        # mean/rstd keep the input's rank with the normalised dims set to 1;
        # normalising over more than one trailing dim is where a flat
        # (M,)-shaped statistic would be caught.
        cases.append(
            _layer_norm_case(
                torch_module, c_module, torch_call, dtype_name,
                _LN_INPUT, (2, 3, 4), [3, 4],
                note="two normalised dims -- mean/rstd are (2,1,1)",
            )
        )
        cases.append(
            _layer_norm_case(
                torch_module, c_module, torch_call, dtype_name,
                _LN_INPUT, (2, 3, 4), [2, 3, 4],
                note="everything normalised -- mean/rstd are (1,1,1)",
            )
        )
        cases.append(
            _layer_norm_case(
                torch_module, c_module, torch_call, dtype_name,
                _LN_INPUT[:8], (2, 4), [4], weight=_LN_WEIGHT, bias=_LN_BIAS,
                note="2-D input -- the shape a flattened GPT-2 block reaches",
            )
        )
        cases.append(
            _layer_norm_case(
                torch_module, c_module, torch_call, dtype_name,
                _LN_INPUT[:4], (4,), [4], note="1-D input -- mean/rstd are (1,)",
            )
        )
    # eps lands on the variance, before the reciprocal square root. These three
    # cases are what pin that: a constant row has zero variance, so its rstd is
    # exactly 1/sqrt(eps) and nothing else.
    for eps, note in [
        (0.0, "eps=0"),
        (1.0, "eps=1 -- large enough that it dominates the variance"),
        (-1.0, "negative eps is not refused upstream; it gives NaN"),
    ]:
        cases.append(
            _layer_norm_case(
                torch_module, c_module, torch_call, "float32",
                _LN_INPUT, (2, 3, 4), [4], eps=eps, note=note,
            )
        )
    cases.append(
        _layer_norm_case(
            torch_module, c_module, torch_call, "float32",
            [1.0] * 8, (2, 4), [4],
            note="constant row -- zero variance, so rstd is exactly 1/sqrt(eps)",
        )
    )
    cases.append(
        _layer_norm_case(
            torch_module, c_module, torch_call, "float32",
            [], (0, 4), [4], note="zero rows -- every result is empty, not an error",
        )
    )
    # Upstream's autocast pairing: a reduced-precision input with float32
    # parameters is *supported*, and it moves mean/rstd to float32 while the
    # output stays reduced. Getting this wrong is invisible in the values and
    # visible only in the dtype, which is why it has its own cases.
    for dtype_name in ["float16", "bfloat16"]:
        cases.append(
            _layer_norm_case(
                torch_module, c_module, torch_call, dtype_name,
                _LN_INPUT, (2, 3, 4), [4], weight=_LN_WEIGHT, bias=_LN_BIAS,
                param_dtype="float32",
                note="mixed dtype: float32 parameters move mean/rstd to float32, output stays reduced",
            )
        )
        cases.append(
            _layer_norm_case(
                torch_module, c_module, torch_call, dtype_name,
                _LN_INPUT, (2, 3, 4), [4], weight=_LN_WEIGHT, param_dtype="float32",
                note="mixed dtype, weight only",
            )
        )
    # Refusals.
    refusals = [
        dict(dtype_name="float32", normalized_shape=[5], note="normalized_shape is not the input's suffix"),
        dict(dtype_name="float32", normalized_shape=[], note="empty normalized_shape"),
        dict(dtype_name="float32", normalized_shape=[2, 3, 4, 5], note="normalized_shape longer than the input"),
        dict(dtype_name="int64", normalized_shape=[4], note="integral input -- no LayerNormKernelImpl"),
    ]
    for spec in refusals:
        flat = _LN_INPUT if spec["dtype_name"] != "int64" else [i % 2 for i in range(24)]
        cases.append(
            _layer_norm_case(
                torch_module, c_module, torch_call, spec["dtype_name"],
                flat, (2, 3, 4), spec["normalized_shape"],
                expect="both_error", note=spec["note"],
            )
        )
    cases.append(
        _layer_norm_case(
            torch_module, c_module, torch_call, "float32",
            _LN_INPUT, (2, 3, 4), [4], weight=[1.0, 2.0, 3.0],
            expect="both_error", note="weight is not normalized_shape's shape",
        )
    )
    cases.append(
        _layer_norm_case(
            torch_module, c_module, torch_call, "float32",
            _LN_INPUT, (2, 3, 4), [4], bias=[1.0, 2.0, 3.0],
            expect="both_error", note="bias is not normalized_shape's shape",
        )
    )
    cases.append(
        _layer_norm_case(
            torch_module, c_module, torch_call, "float32",
            _LN_INPUT, (2, 3, 4), [4], weight=_LN_WEIGHT, param_dtype="float16",
            expect="both_error",
            note="float32 input with float16 parameters -- 'mixed dtype (CPU)' on both sides",
        )
    )
    cases.append(
        _layer_norm_case(
            torch_module, c_module, torch_call, "float64",
            _LN_INPUT, (2, 3, 4), [4], weight=_LN_WEIGHT, param_dtype="float32",
            expect="both_error",
            note="float64 input with float32 parameters -- torch refuses this pairing too",
        )
    )
    # A zero-extent normalised dimension: torch answers with mean=0 and
    # rstd=nan, which do not describe the same reduction. The shim refuses by
    # name rather than reproducing an inconsistency from a single observation.
    cases.append(
        Case(
            name="native_layer_norm(normalized_shape=[0]) [torch answers mean=0 with rstd=nan; the shim refuses]",
            op="aten.native_layer_norm.default",
            run_torch=lambda: torch_call(
                torch_module.zeros(2, 0), [0], None, None, 1e-5
            ),
            run_c=lambda: c_module._aten_dispatch(
                "aten.native_layer_norm.default",
                c_module._tensor_from_flat([], [2, 0], dtype=c_module.float32),
                [0], None, None, 1e-5,
            ),
            expect="c_error",
            note="documented gap: upstream's mean (0) and rstd (nan) disagree about "
                 "what a reduction over no elements is, and one observation is not "
                 "enough to reproduce that. See rust/torch_c/src/aten.rs.",
        )
    )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # input/normalized_shape/weight/bias/eps all by keyword. `input`, not
    # `self`, is this schema's own name for the tensor argument.
    kw_x_t, kw_x_c = pair_from_flat(torch_module, c_module, _LN_INPUT, (2, 3, 4), "float32")
    kw_w_t, kw_w_c = pair_from_flat(torch_module, c_module, _LN_WEIGHT, (4,), "float32")
    kw_b_t, kw_b_c = pair_from_flat(torch_module, c_module, _LN_BIAS, (4,), "float32")
    cases.append(
        Case(
            name="native_layer_norm(input=/normalized_shape=/weight=/bias=/eps= all by keyword)",
            op="aten.native_layer_norm.default",
            run_torch=lambda: torch_call(input=kw_x_t, normalized_shape=[4], weight=kw_w_t, bias=kw_b_t, eps=1e-5),
            run_c=lambda: c_module._aten_dispatch(
                "aten.native_layer_norm.default",
                input=kw_x_c, normalized_shape=[4], weight=kw_w_c, bias=kw_b_c, eps=1e-5,
            ),
            value_check=_triple_result_check,
        )
    )
    return cases


# --- aten.native_group_norm.default -----------------------------------------
#
# `sew_d`'s wall. Three results again, so `_triple_result_check` above does the
# comparing -- and here the second and third matter more than they did for
# `native_layer_norm`, because *nothing* reads them. `torch.group_norm` returns
# `result[0]`; a `mean` of the wrong shape, the wrong dtype, or the wrong
# definition entirely leaves every forward in the sweep green.
#
# `C = 6` with `group = 3` throughout, which is the only configuration that
# separates the two views this kernel needs. The statistics are over
# `(C/group) * HxW` and the affine parameters are over `C`, and those two
# coincide when `group == C` (InstanceNorm) or `group == 1` (LayerNorm over
# C,H,W) -- the two a hand-written test picks first. With `C/group == 2` they
# do not, so a kernel that used one view for both fails on values.

_GROUP_NORM_DTYPES = ["float64", "float32", "float16", "bfloat16"]
# 36 values that are not a smooth ramp along any single axis, so a wrong
# reduction axis shows up as a wrong number rather than as the same number by
# symmetry. `(1, 6, 6)` is N=1, C=6, HxW=6.
_GN_INPUT = [round(((i * 37) % 23) / 7.0 - 1.5, 6) for i in range(36)]
_GN_WEIGHT = [1.0, 2.0, 0.5, -1.0, 0.25, 3.0]
_GN_BIAS = [0.1, 0.2, 0.3, 0.4, -0.5, 0.6]


def _group_norm_case(
    torch_module, c_module, torch_call, dtype_name, flat, shape, n, c, hxw, group,
    weight=None, bias=None, eps=1e-5, param_dtype=None, expect="match", note="",
) -> Case:
    op = "aten.native_group_norm.default"
    param_dtype = param_dtype or dtype_name
    x_t, x_c = pair_from_flat(torch_module, c_module, flat, shape, dtype_name)
    if weight is None:
        w_t = w_c = None
    else:
        w_t, w_c = pair_from_flat(torch_module, c_module, weight, (len(weight),), param_dtype)
    if bias is None:
        b_t = b_c = None
    else:
        b_t, b_c = pair_from_flat(torch_module, c_module, bias, (len(bias),), param_dtype)
    return Case(
        name=(
            f"native_group_norm(dtype={dtype_name}, shape={shape}, N={n}, C={c}, "
            f"HxW={hxw}, group={group}, weight={weight is not None}, "
            f"bias={bias is not None}, eps={eps}, param_dtype={param_dtype}) [{note}]"
        ),
        op=op,
        run_torch=lambda: torch_call(x_t, w_t, b_t, n, c, hxw, group, eps),
        run_c=lambda: c_module._aten_dispatch(op, x_c, w_c, b_c, n, c, hxw, group, eps),
        expect=expect,
        value_check=_triple_result_check if expect == "match" else None,
        note=note + " -- returns (out, mean, rstd), see _triple_result_check",
    )


def native_group_norm_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.native_group_norm.default"
    cases: list[Case] = []

    for dtype_name in _GROUP_NORM_DTYPES:
        for weight, bias, note in [
            (_GN_WEIGHT, _GN_BIAS, "weight and bias -- nn.GroupNorm's default"),
            (None, None, "affine=False"),
            (_GN_WEIGHT, None, "weight only"),
            (None, _GN_BIAS, "bias only"),
        ]:
            cases.append(
                _group_norm_case(
                    torch_module, c_module, torch_call, dtype_name,
                    _GN_INPUT, (1, 6, 6), 1, 6, 6, 3, weight=weight, bias=bias,
                    note=note,
                )
            )
        # Two samples, so a kernel that reduced over the batch as well as over
        # the group produces one statistic where there should be two. `(2,6,3)`
        # is N=2, C=6, HxW=3 over the same 36 values.
        cases.append(
            _group_norm_case(
                torch_module, c_module, torch_call, dtype_name,
                _GN_INPUT, (2, 6, 3), 2, 6, 3, 3, weight=_GN_WEIGHT, bias=_GN_BIAS,
                note="N=2: the statistics are per (sample, group), not per group",
            )
        )
        # A rank-4 input, the shape `nn.GroupNorm` is usually written for.
        cases.append(
            _group_norm_case(
                torch_module, c_module, torch_call, dtype_name,
                _GN_INPUT, (1, 6, 2, 3), 1, 6, 6, 3, weight=_GN_WEIGHT, bias=_GN_BIAS,
                note="rank 4 (N,C,H,W): HxW is the product of the trailing axes",
            )
        )

    # `group` at both ends. These two are where the statistics view and the
    # affine view coincide, so they are here as the control rather than as the
    # coverage -- a kernel that passes ONLY these is the one this file is
    # guarding against.
    for group, note in (
        (1, "group=1 -- LayerNorm over (C,H,W); the two views coincide"),
        (6, "group=C -- InstanceNorm; the two views coincide here too"),
    ):
        cases.append(
            _group_norm_case(
                torch_module, c_module, torch_call, "float32",
                _GN_INPUT, (1, 6, 6), 1, 6, 6, group,
                weight=_GN_WEIGHT, bias=_GN_BIAS, note=note,
            )
        )

    # A CONSTANT group. This is the case that pins where `eps` goes and it
    # cannot be replaced by a random one: the variance is 0, so
    # `rstd = 1/sqrt(0+eps) = 316.2278` at eps=1e-5, while `1/(sqrt(0)+eps)`
    # would be 100000 and `sqrt(0+eps)` would be 0.00316. All three have the
    # same shape and dtype. Conversely a random group cannot pin it, because
    # eps is negligible against a real variance -- so both cases are needed and
    # neither is redundant.
    cases.append(
        _group_norm_case(
            torch_module, c_module, torch_call, "float32",
            [3.0] * 36, (1, 6, 6), 1, 6, 6, 3,
            note="constant input: rstd is 1/sqrt(eps)=316.2278, which pins eps's place",
        )
    )
    # ...and with a larger eps, so that "eps is negligible" cannot hide a
    # misplacement on the non-constant data either.
    cases.append(
        _group_norm_case(
            torch_module, c_module, torch_call, "float32",
            _GN_INPUT, (1, 6, 6), 1, 6, 6, 3, eps=0.5,
            note="eps=0.5 on real data: large enough to move rstd visibly",
        )
    )
    # A negative eps is NOT refused: it gives NaN where var+eps < 0 and a
    # finite answer elsewhere. `_triple_result_check` compares NaN to NaN.
    cases.append(
        _group_norm_case(
            torch_module, c_module, torch_call, "float32",
            _GN_INPUT, (1, 6, 6), 1, 6, 6, 3, eps=-1.0,
            note="negative eps is not refused -- NaN where var+eps is negative",
        )
    )
    # An empty batch: every result is empty, and there is no inconsistency to
    # reproduce (unlike HxW=0 below).
    cases.append(
        _group_norm_case(
            torch_module, c_module, torch_call, "float32",
            [], (0, 6, 4), 0, 6, 4, 3,
            note="N=0: out is (0,6,4), mean/rstd are (0,3)",
        )
    )

    # The mixed-precision pairing: reduced input with float32 parameters gives
    # float32 statistics and a reduced output. That combination is *supported*
    # upstream, not an error, and it is the one where a kernel that tagged the
    # statistics with the input dtype passes every other case.
    for dtype_name in ["float16", "bfloat16"]:
        cases.append(
            _group_norm_case(
                torch_module, c_module, torch_call, dtype_name,
                _GN_INPUT, (1, 6, 6), 1, 6, 6, 3,
                weight=_GN_WEIGHT, bias=_GN_BIAS, param_dtype="float32",
                note="autocast pairing: out is reduced, mean/rstd are float32",
            )
        )
    # ...and the pairings upstream refuses.
    cases.append(
        _group_norm_case(
            torch_module, c_module, torch_call, "float32",
            _GN_INPUT, (1, 6, 6), 1, 6, 6, 3, weight=_GN_WEIGHT, param_dtype="float16",
            expect="both_error",
            note="float32 input with float16 parameters -- 'mixed dtype (CPU)' on both sides",
        )
    )
    cases.append(
        _group_norm_case(
            torch_module, c_module, torch_call, "float32",
            _GN_INPUT, (1, 6, 6), 1, 6, 6, 3, weight=_GN_WEIGHT, param_dtype="float64",
            expect="both_error",
            note="float32 input with float64 parameters -- refused too",
        )
    )

    # The refusals, each with its own message upstream.
    for dtype_name in ["int64", "bool"]:
        flat = [1] * 36 if dtype_name == "bool" else list(range(36))
        cases.append(
            _group_norm_case(
                torch_module, c_module, torch_call, dtype_name,
                flat, (1, 6, 6), 1, 6, 6, 3, expect="both_error",
                note='"GroupNormKernelImpl" not implemented for this dtype',
            )
        )
    cases.append(
        _group_norm_case(
            torch_module, c_module, torch_call, "float32",
            _GN_INPUT, (1, 6, 6), 1, 6, 6, 4, expect="both_error",
            note="C=6 is not divisible by group=4",
        )
    )
    cases.append(
        _group_norm_case(
            torch_module, c_module, torch_call, "float32",
            _GN_INPUT, (1, 6, 6), 1, 6, 7, 3, expect="both_error",
            note="N*C*HxW does not equal numel",
        )
    )
    cases.append(
        _group_norm_case(
            torch_module, c_module, torch_call, "float32",
            _GN_INPUT, (1, 6, 6), 1, 6, 6, 0, expect="both_error",
            note="group=0 -- 'Expected num groups to be greater than 0'",
        )
    )
    cases.append(
        _group_norm_case(
            torch_module, c_module, torch_call, "float32",
            _GN_INPUT, (1, 6, 6), 1, 6, 6, 3, weight=[1.0, 2.0, 3.0],
            expect="both_error",
            note="weight is not a vector of length C",
        )
    )

    # HxW == 0: upstream answers mean=0 with rstd=nan, which do not describe
    # the same reduction. The shim refuses by name, exactly as
    # `native_layer_norm` refuses a zero-extent normalized_shape.
    cases.append(
        _group_norm_case(
            torch_module, c_module, torch_call, "float32",
            [], (2, 6, 0), 2, 6, 0, 3, expect="c_error",
            note="documented gap: upstream's mean (0) and rstd (nan) disagree about what "
                 "a reduction over no elements is; see rust/torch_c/src/aten.rs",
        )
    )

    # Keyword-argument coverage. `input`, not `self`, is this schema's name for
    # the tensor.
    kw_x_t, kw_x_c = pair_from_flat(torch_module, c_module, _GN_INPUT, (1, 6, 6), "float32")
    kw_w_t, kw_w_c = pair_from_flat(torch_module, c_module, _GN_WEIGHT, (6,), "float32")
    kw_b_t, kw_b_c = pair_from_flat(torch_module, c_module, _GN_BIAS, (6,), "float32")
    cases.append(
        Case(
            name="native_group_norm(input=/weight=/bias=/N=/C=/HxW=/group=/eps= all by keyword)",
            op=op,
            run_torch=lambda: torch_call(
                input=kw_x_t, weight=kw_w_t, bias=kw_b_t, N=1, C=6, HxW=6, group=3, eps=1e-5),
            run_c=lambda: c_module._aten_dispatch(
                op, input=kw_x_c, weight=kw_w_c, bias=kw_b_c, N=1, C=6, HxW=6,
                group=3, eps=1e-5),
            value_check=_triple_result_check,
        )
    )

    cases.extend(_group_norm_spelling_cases(torch_module, c_module))
    return cases


def _group_norm_spelling_cases(torch_module, c_module) -> list[Case]:
    """`torch.group_norm(x, num_groups, w, b, eps, cudnn)` -- the composite.

    `sew_d` never spells the leaf op: `nn.GroupNorm.forward` calls
    `F.group_norm`, which calls `torch.group_norm`, which is
    `CompositeImplicitAutograd` and derives `N`, `C` and `HxW` from the input's
    shape before reaching `native_group_norm`. Golden compares by dispatch key
    and is structurally blind to that whole derivation -- so deleting the
    composite from `bootstrap.py`, or getting `HxW` wrong in it, fails here and
    nothing else.

    The rank-4 case is the one that matters: with `(1, 6, 2, 3)` the composite
    has to multiply the two trailing axes, and a body that used `shape[2]`
    would pass every rank-3 case and fail this one.
    """
    op = "aten.native_group_norm.default"
    cases: list[Case] = []
    for shape in ((1, 6, 6), (2, 6, 3), (1, 6, 2, 3)):
        for weight, bias, label in (
            (_GN_WEIGHT, _GN_BIAS, "affine"),
            (None, None, "affine=False"),
        ):
            pairs = [pair_from_flat(torch_module, c_module, _GN_INPUT, shape, "float32")]
            if weight is not None:
                pairs.append(
                    pair_from_flat(torch_module, c_module, weight, (6,), "float32"))
                pairs.append(
                    pair_from_flat(torch_module, c_module, bias, (6,), "float32"))
                call = (lambda m, x, w, b:
                        _free(m, "group_norm")(x, 3, w, b, 1e-5, True))
            else:
                call = lambda m, x: _free(m, "group_norm")(x, 3, None, None, 1e-5, True)
            cases.append(
                _member_case(
                    torch_module, c_module, op,
                    f"composite torch.group_norm(x{shape}, 3, {label})", "float32",
                    pairs, call,
                    note="F.group_norm's own call shape; N/C/HxW derived from the input",
                )
            )
    # Rank 1 is refused by the composite before it reaches any kernel, and the
    # message is the composite's own.
    pair = pair_from_flat(torch_module, c_module, [1.0, 2.0, 3.0], (3,), "float32")
    cases.append(
        _member_case(
            torch_module, c_module, op,
            "composite torch.group_norm(rank-1) [refused before dispatch]", "float32",
            [pair], lambda m, x: _free(m, "group_norm")(x, 3, None, None, 1e-5, True),
            expect="both_error",
            note="'Expected at least 2 dimensions for input tensor'",
        )
    )
    return cases


# --- aten.upsample_bilinear2d.default ---------------------------------------
#
# `zoedepth`'s wall, and the op where the wrong answer is a *plausible image*.
# `align_corners` selects between two different sampling grids, and they agree
# at the four corners -- which is what the flag means -- so a case set built
# from corners, or from a symmetric input, cannot separate them at all. The
# input below is a non-symmetric ramp and every case runs both values of the
# flag.
#
# Measured on `arange(6).reshape(1,1,2,3)` -> `(4,6)`, the two disagree on 20
# of 24 elements:
#
#     align_corners=False   0.00 0.25 0.75 1.25 1.75 2.00 | 0.75 1.00 ...
#     align_corners=True    0.00 0.40 0.80 1.20 1.60 2.00 | 1.00 1.40 ...

_BILINEAR_DTYPES = ["float64", "float32", "float16", "bfloat16"]
# A non-symmetric ramp on a non-square input: (1, 1, 2, 3). Symmetric data or a
# square input lets an H/W mix-up through.
_UB_INPUT = [0.0, 1.0, 2.0, 3.0, 4.0, 5.0]
_UB_SHAPE = (1, 1, 2, 3)


def _bilinear_case(
    torch_module, c_module, torch_call, dtype_name, flat, shape, output_size,
    align_corners, scales_h=None, scales_w=None, expect="match", note="",
) -> Case:
    op = "aten.upsample_bilinear2d.default"
    x_t, x_c = pair_from_flat(torch_module, c_module, flat, shape, dtype_name)
    return Case(
        name=(
            f"upsample_bilinear2d(dtype={dtype_name}, shape={shape}, "
            f"output_size={output_size}, align_corners={align_corners}, "
            f"scales=({scales_h}, {scales_w})) [{note}]"
        ),
        op=op,
        run_torch=lambda: torch_call(x_t, output_size, align_corners, scales_h, scales_w),
        run_c=lambda: c_module._aten_dispatch(
            op, x_c, output_size, align_corners, scales_h, scales_w),
        expect=expect,
        note=note,
    )


def upsample_bilinear2d_cases(torch_module, c_module, torch_call) -> list[Case]:
    """`aten.upsample_bilinear2d(self, output_size, align_corners, scales_h, scales_w)`.

    The plausible wrong implementations, and what separates each:

      * **dropping the half-pixel offset** under `align_corners=False` --
        `scale * d` instead of `scale * (d + 0.5) - 0.5`. Produces a plausible,
        slightly-shifted image. Every `align_corners=False` case with a
        non-symmetric input separates it; a corner-only or symmetric case does
        not.
      * **implementing one convention for both flag values** -- the pairs
        below run identical inputs through both, so the two must differ.
      * **ignoring `scales_h`/`scales_w` and using `in/out`** -- identical
        whenever `out == in * scale` exactly, which is every `scale_factor=2`
        case. The `in=3, out=4, scale=1.5` case is the one that separates it.
      * **honouring a non-positive scale** -- upstream ignores `0.0` and
        `-1.0` and falls back to `in/out`; a kernel that divided by them
        produces `inf` or a mirrored grid.
      * **resampling when `out == in`** -- upstream copies the axis outright,
        even when a supplied scale says the grid is not the identity.
      * **computing in the widest available type** -- `float32` computed in
        `f64` differs from upstream on 241 of 286 elements. That one is a
        precision fault the tolerance *can* see, unlike sigmoid's, because it
        is the grid arithmetic and not the last rounding.
      * **transposing H and W** -- every shape here is non-square.
    """
    op = "aten.upsample_bilinear2d.default"
    cases: list[Case] = []

    for dtype_name in _BILINEAR_DTYPES:
        for align_corners in (False, True):
            for output_size, note in (
                ([4, 6], "2x upsample, both axes"),
                ([4, 5], "a non-integral ratio on W"),
                ([3, 7], "different ratios per axis"),
                ([1, 2], "downsample"),
                ([1, 1], "collapse to a single pixel"),
                ([2, 3], "out == in: the axis is copied, not resampled"),
                ([2, 6], "one axis unchanged, the other upsampled"),
            ):
                cases.append(
                    _bilinear_case(
                        torch_module, c_module, torch_call, dtype_name,
                        _UB_INPUT, _UB_SHAPE, output_size, align_corners, note=note,
                    )
                )
        # More than one plane, so that a kernel indexing a single (H, W) plane
        # and then repeating it fails.
        for align_corners in (False, True):
            cases.append(
                _bilinear_case(
                    torch_module, c_module, torch_call, dtype_name,
                    [float(i) for i in range(24)], (2, 2, 2, 3), [4, 6], align_corners,
                    note="N=2, C=2: four distinct planes",
                )
            )

    # The scales. `1/scale` versus `in/out`, on the one geometry where they
    # differ: in=3, out=4, scale=1.5 gives 0.6667 against 0.75, and upstream
    # answers [0, 0.5, 1.1667, 1.8333] rather than [0, 0.625, 1.375, 2].
    row = [0.0, 1.0, 2.0]
    for scales_w, note in (
        (1.5, "scale 1.5 -> 1/1.5 = 0.667, NOT in/out = 0.75"),
        (2.0, "scale 2.0 -> 0.5, also not in/out here"),
        (0.0, "a zero scale is IGNORED, falling back to in/out"),
        (-1.0, "a negative scale is ignored too"),
        (None, "the baseline both of the above fall back to"),
    ):
        cases.append(
            _bilinear_case(
                torch_module, c_module, torch_call, "float32",
                row, (1, 1, 1, 3), [1, 4], False, scales_w=scales_w, note=note,
            )
        )
    # `align_corners=True` ignores the scales entirely -- measured with a scale
    # large enough that honouring it would be unmissable.
    for scales_w in (None, 9.0):
        cases.append(
            _bilinear_case(
                torch_module, c_module, torch_call, "float32",
                row, (1, 1, 1, 3), [1, 4], True, scales_w=scales_w,
                note="align_corners=True ignores the scales",
            )
        )
    # ...and the copy short-circuit survives a scale that says otherwise.
    cases.append(
        _bilinear_case(
            torch_module, c_module, torch_call, "float32",
            row, (1, 1, 1, 3), [1, 3], False, scales_w=0.5,
            note="out == in copies the axis even with a scale of 0.5",
        )
    )

    # An empty batch: the answer is empty, not an error. `C == 0` IS an error.
    cases.append(
        _bilinear_case(
            torch_module, c_module, torch_call, "float32",
            [], (0, 1, 2, 3), [4, 6], False, note="N=0 gives an empty (0,1,4,6)",
        )
    )
    cases.append(
        _bilinear_case(
            torch_module, c_module, torch_call, "float32",
            [], (1, 0, 2, 3), [4, 6], False, expect="both_error",
            note="C=0 -- 'Non-empty 4D data tensor expected'",
        )
    )

    # The refusals, in upstream's order.
    cases.append(
        _bilinear_case(
            torch_module, c_module, torch_call, "float32",
            _UB_INPUT, _UB_SHAPE, [4], False, expect="both_error",
            note="output_size must have length 2",
        )
    )
    cases.append(
        _bilinear_case(
            torch_module, c_module, torch_call, "float32",
            _UB_INPUT, (1, 2, 3), [4, 6], False, expect="both_error",
            note="the input must be rank 4",
        )
    )
    for output_size, note in (([0, 3], "a zero output extent"),
                              ([-1, 3], "a negative output extent")):
        cases.append(
            _bilinear_case(
                torch_module, c_module, torch_call, "float32",
                _UB_INPUT, _UB_SHAPE, output_size, False, expect="both_error", note=note,
            )
        )
    for dtype_name in ("int64", "bool"):
        flat = [1] * 6 if dtype_name == "bool" else [0, 1, 2, 3, 4, 5]
        cases.append(
            _bilinear_case(
                torch_module, c_module, torch_call, dtype_name,
                flat, _UB_SHAPE, [4, 6], False, expect="both_error",
                note='"upsample_bilinear2d_channels_last" not implemented for this dtype',
            )
        )
    # `uint8` is the documented gap: upstream computes it with a separate
    # fixed-point kernel, and round-half-away-from-zero on the float32 answer
    # disagrees with it on 355 of 5584 measured elements. Refused by name.
    cases.append(
        _bilinear_case(
            torch_module, c_module, torch_call, "uint8",
            [0, 10, 20, 30, 40, 50], _UB_SHAPE, [4, 6], False, expect="c_error",
            note="documented gap: upstream's uint8 path is not 'bilinear then round'",
        )
    )

    # Keyword-argument coverage.
    kw_t, kw_c = pair_from_flat(torch_module, c_module, _UB_INPUT, _UB_SHAPE, "float32")
    cases.append(
        Case(
            name="upsample_bilinear2d(self=/output_size=/align_corners=/scales_h=/scales_w=)",
            op=op,
            run_torch=lambda: torch_call(
                self=kw_t, output_size=[4, 6], align_corners=False,
                scales_h=2.0, scales_w=2.0),
            run_c=lambda: c_module._aten_dispatch(
                op, self=kw_c, output_size=[4, 6], align_corners=False,
                scales_h=2.0, scales_w=2.0),
        )
    )

    cases.extend(_bilinear_vec_cases(torch_module, c_module))
    return cases


def _bilinear_vec_cases(torch_module, c_module) -> list[Case]:
    """`torch._C._nn.upsample_bilinear2d(input, output_size, align_corners,
    scale_factors)` -- the `.vec` spelling `F.interpolate` actually calls.

    `zoedepth` never spells the leaf: `F.interpolate(x, scale_factor=2,
    mode="bilinear", align_corners=...)` calls this four-argument form, which
    derives the output size and forwards the factors. Golden compares by
    dispatch key and is blind to that derivation.

    The `scale_factor=1.5` case is the one that matters. Upstream's
    `compute_output_size` floors, so `in=3` gives `out=4`, and then the *leaf*
    is called with `scales_w=1.5` rather than deriving `3/4` -- a composite
    that only sized the output and dropped the factors samples a different
    grid, with the right shape.
    """
    op = "aten.upsample_bilinear2d.default"
    cases: list[Case] = []

    def vec(m, x, output_size, align_corners, factors):
        # `torch` keeps this on `torch._C._nn`; the shim module *is* `_C`, so
        # its copy is `_C._nn`. Reaching for the wrong one gets an
        # `AttributeError`, which the harness correctly reports as a divergence
        # -- and which, on a `c_error` case, would have "passed".
        nn = m._nn if hasattr(m, "_nn") else m._C._nn
        return nn.upsample_bilinear2d(x, output_size, align_corners, factors)

    for align_corners in (False, True):
        for output_size, factors, label in (
            (None, [2.0, 2.0], "scale_factor=2"),
            (None, [1.5, 1.5], "scale_factor=1.5 -- floors the size, forwards the factor"),
            (None, [3.0, 1.0], "different factors per axis"),
            ([4, 6], None, "an explicit output_size instead"),
        ):
            pair = pair_from_flat(torch_module, c_module, _UB_INPUT, _UB_SHAPE, "float32")
            cases.append(
                _member_case(
                    torch_module, c_module, op,
                    f"_nn.upsample_bilinear2d({label}, align_corners={align_corners})",
                    "float32", [pair],
                    lambda m, x, o=output_size, a=align_corners, f=factors: vec(m, x, o, a, f),
                    note="F.interpolate's own call shape",
                )
            )
    # **Both** given is refused, not "output_size wins". This case was written
    # the other way first and caught the composite computing where upstream
    # raises `Must specify exactly one of output_size and scale_factors` --
    # which is the whole reason the `.vec` spelling has cases at all, since no
    # dispatch key exists for it.
    for both in ((None, None), ([5, 5], [2.0, 2.0])):
        pair = pair_from_flat(torch_module, c_module, _UB_INPUT, _UB_SHAPE, "float32")
        cases.append(
            _member_case(
                torch_module, c_module, op,
                f"_nn.upsample_bilinear2d(output_size={both[0]}, factors={both[1]}) [refused]",
                "float32", [pair],
                lambda m, x, o=both[0], f=both[1]: vec(m, x, o, False, f),
                expect="both_error",
                note="exactly one of output_size and scale_factors, measured",
            )
        )
    return cases


# --- aten.gelu.default -------------------------------------------------------
#
# The op with two functions behind one name. `approximate="none"` is the exact
# erf form, `approximate="tanh"` is Hendrycks' cubic; on `[-3, 3]` in float32
# they differ by up to **4.12e-04**, against this harness's float32 tolerance of
# 1e-5. So the three variants below (default / explicit "none" / explicit
# "tanh") are not redundant coverage -- the default-vs-tanh pair is a live trap
# for a shim that picked the wrong formula for the unqualified call, and it
# would fire with 40x the tolerance, not at the edge of it.
#
# Measured (docs/ARCH.md §2): Gemma and Gemma-2 pass `"tanh"`; BERT, RoBERTa,
# ELECTRA, DistilBERT, DeBERTa-v2, BART, Falcon, GPT-NeoX, GPT-BigCode,
# Starcoder2, MPT and ViT all take the default.

_GELU_DTYPES = ["float64", "float32", "float16", "bfloat16"]
_GELU_APPROX: list[tuple[dict, str]] = [
    ({}, "unqualified -- upstream's schema default is 'none', the erf form"),
    ({"approximate": "none"}, "explicit 'none' -- must equal the unqualified call"),
    ({"approximate": "tanh"}, "explicit 'tanh' -- Gemma's gelu_pytorch_tanh"),
]
_GELU_SCENARIOS: list[tuple[list, tuple, str]] = [
    ([-3.0, -1.0, -0.5, 0.0], (2, 2), "the negative lobe, where the two formulas diverge most"),
    ([0.5, 1.0, 2.0, 3.0], (2, 2), "the positive side"),
    ([-8.0, 8.0, -0.001, 0.001], (2, 2), "saturating tails and near-zero"),
    ([0.5], (), "0-d"),
    ([], (0,), "empty"),
]


def gelu_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.gelu.default"
    cases: list[Case] = []
    for dtype_name in _GELU_DTYPES:
        for kwargs, kw_note in _GELU_APPROX:
            for flat, shape, note in _GELU_SCENARIOS:
                cases.append(
                    _unary_case(
                        torch_module, c_module, op, torch_call, dtype_name, flat, shape,
                        f"{note}; {kw_note}", kwargs=kwargs,
                    )
                )
        # gelu(-inf) is `nan`, not 0: the exact form multiplies -inf by
        # (1 + erf(-inf)) == 0, and the tanh form multiplies it by
        # (1 + tanh(-inf)) == 0. Both give the indeterminate product, on both
        # sides. Kept because a kernel written as "clamp then scale" would give
        # -0.0 here and pass every other case in this file.
        for kwargs, kw_note in _GELU_APPROX:
            cases.append(
                _unary_case(
                    torch_module, c_module, op, torch_call, dtype_name,
                    [float("nan"), float("inf"), float("-inf")], (3,),
                    f"nan/+-inf -- +inf passes through, -inf gives NaN; {kw_note}",
                    kwargs=kwargs,
                )
            )

    # The refusals. This is `silu`'s side of the promotion split, not
    # `tanh`'s: there is no GeluKernelImpl for an integral or boolean input,
    # so a shim built on the promoting unary helper would compute where torch
    # raises. bool is deferred into the lambdas for the usual reason (see
    # masked_fill_cases).
    for dtype_name in ["int64", "int32", "int16", "uint8"]:
        a_t, a_c = pair_from_flat(torch_module, c_module, [0, 1, 2, 3], (2, 2), dtype_name)
        cases.append(
            Case(
                name=f"gelu(dtype={dtype_name}) [no GeluKernelImpl for an integral input]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c),
                expect="both_error",
                note="torch: NotImplementedError(\"GeluKernelImpl\" not implemented for 'Long').",
            )
        )
    cases.append(
        Case(
            name="gelu(dtype=bool) [no GeluKernelImpl for a mask either]",
            op=op,
            run_torch=lambda: torch_call(torch_module.tensor([True, False])),
            run_c=lambda: c_module._aten_dispatch(
                op, c_module._tensor_from_flat([1, 0], [2], dtype=c_module.bool)
            ),
            expect="both_error",
            note="torch: NotImplementedError(\"GeluKernelImpl\" not implemented for 'Bool').",
        )
    )

    # The two ways to get `approximate` wrong. Both are RuntimeErrors upstream
    # and both must stay refusals: a shim that fell back to "none" on an
    # unrecognised string would answer a Gemma typo with a BERT activation.
    x_t, x_c = pair_from_flat(torch_module, c_module, [1.0, -1.0], (2,), "float32")
    for bad in ["TANH", "erf", ""]:
        cases.append(
            Case(
                name=f"gelu(approximate={bad!r}) [only 'none' and 'tanh' exist]",
                op=op,
                run_torch=lambda x_t=x_t, bad=bad: torch_call(x_t, approximate=bad),
                run_c=lambda x_c=x_c, bad=bad: c_module._aten_dispatch(op, x_c, approximate=bad),
                expect="both_error",
                note="torch: 'approximate argument must be either none or tanh.'",
            )
        )
    cases.append(
        Case(
            name="gelu(x, 'tanh') positionally [approximate is keyword-only]",
            op=op,
            run_torch=lambda: torch_call(x_t, "tanh"),
            run_c=lambda: c_module._aten_dispatch(op, x_c, "tanh"),
            expect="both_error",
            note=(
                "The schema is `gelu(Tensor self, *, str approximate=\"none\")`. Accepting "
                "the positional form would let `gelu(x, 'tanh')` mean the tanh formula in "
                "the shim and be an error upstream -- divergence in the loudest direction."
            ),
        )
    )
    cases.append(
        Case(
            name="gelu(approximate=None) [the schema says str, not str?]",
            op=op,
            run_torch=lambda: torch_call(x_t, approximate=None),
            run_c=lambda: c_module._aten_dispatch(op, x_c, approximate=None),
            expect="both_error",
            note="torch: Expected a value of type 'str' ... but instead found type 'NoneType'.",
        )
    )
    return cases


# --- aten.gather.default -----------------------------------------------------
#
# `scatter.src` read backwards. The cases below are the three places candle's
# own `Tensor::gather` and torch disagree (index dtype, out-of-range handling,
# contiguity), plus the rank rule that is easy to get wrong in the safe-looking
# direction -- see the kernel's docstring in rust/torch_c/src/aten.rs.

_GATHER_SELF = ([1.0, 2.0, 3.0, 4.0, 5.0, 6.0], (2, 3))


def _gather_case(torch_module, c_module, torch_call, dtype_name, self_flat, self_shape,
                 dim, idx_flat, idx_shape, idx_dtype="int64", kwargs=None,
                 expect="match", note="") -> Case:
    op = "aten.gather.default"
    kwargs = kwargs or {}
    s_t, s_c = pair_from_flat(torch_module, c_module, self_flat, self_shape, dtype_name)
    i_t, i_c = pair_from_flat(torch_module, c_module, idx_flat, idx_shape, idx_dtype)
    return Case(
        name=f"gather(dtype={dtype_name}, self={self_shape}, dim={dim}, "
             f"index={idx_shape}/{idx_dtype}) [{note}]",
        op=op,
        run_torch=lambda: torch_call(s_t, dim, i_t, **kwargs),
        run_c=lambda: c_module._aten_dispatch(op, s_c, dim, i_c, **kwargs),
        expect=expect,
        note=note,
    )


def gather_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.gather.default"
    flat, shape = _GATHER_SELF
    cases: list[Case] = []

    # Every storable dtype, including bool -- gather moves bits, it does not
    # compute, so there is no kernel-coverage split here the way there is for
    # mm. bool goes through the deferred-construction form.
    for dtype_name in ["float64", "float32", "float16", "bfloat16",
                       "int64", "int32", "int16", "uint8"]:
        cases.append(
            _gather_case(torch_module, c_module, torch_call, dtype_name, flat, shape,
                         1, [0, 2, 1, 0], (2, 2), note="along the last dim")
        )
    cases.append(
        Case(
            name="gather(dtype=bool, dim=1) [a mask is gathered like anything else]",
            op=op,
            run_torch=lambda: torch_call(
                torch_module.tensor([[True, False, True], [False, True, False]]),
                1,
                torch_module.tensor([[0, 2], [1, 0]]),
            ),
            run_c=lambda: c_module._aten_dispatch(
                op,
                c_module._tensor_from_flat([1, 0, 1, 0, 1, 0], [2, 3], dtype=c_module.bool),
                1,
                c_module._tensor_from_flat([0, 2, 1, 0], [2, 2], dtype=c_module.int64),
            ),
            note="the bool tag has to survive the round trip through the flat reader",
        )
    )

    # Shape and axis coverage.
    for dim, idx_flat, idx_shape, note in [
        (0, [0, 1, 0, 1, 0, 1], (2, 3), "along dim 0"),
        (-1, [0, 1, 1, 0], (2, 2), "negative dim"),
        (1, [0], (1, 1), "index SMALLER than self off-axis -- the extra row is never read"),
        (1, [0, 1, 2, 0, 1], (1, 5), "index LONGER than self along the axis -- values repeat"),
        (1, [], (2, 0), "empty index gives an empty result, not an error"),
        (1, [2, 2, 2, 2, 2, 2], (2, 3), "every index the same -- a broadcast written as a gather"),
    ]:
        cases.append(
            _gather_case(torch_module, c_module, torch_call, "float32", flat, shape,
                         dim, idx_flat, idx_shape, note=note)
        )
    cases.append(
        _gather_case(torch_module, c_module, torch_call, "float32", flat, shape,
                     1, [0, 2, 1, 0], (2, 2), idx_dtype="int32",
                     note="int32 index -- torch accepts exactly int32 and int64")
    )
    cases.append(
        _gather_case(torch_module, c_module, torch_call, "float32", flat, shape,
                     1, [0, 1], (1, 2), kwargs={"sparse_grad": True},
                     note="sparse_grad picks an autograd representation; the forward answer "
                          "is identical either way (measured)")
    )
    # 3-d, which is the shape BERT's path actually produces.
    cases.append(
        _gather_case(
            torch_module, c_module, torch_call, "float32",
            [float(i) for i in range(24)], (2, 3, 4), 2,
            [0, 3, 1, 2, 3, 0, 2, 2, 0, 1, 3, 3], (2, 3, 2),
            note="3-d gather along the last axis",
        )
    )

    # The rank rule, which is `max(rank, 1)` on BOTH sides and not "the ranks
    # must be equal". Guessing the stricter rule refuses two calls torch
    # answers; guessing a looser one accepts a call torch refuses.
    cases.append(
        _gather_case(torch_module, c_module, torch_call, "float32", [7.0], (), 0,
                     [0, 0], (2,), note="0-d self with a 1-d index -> shape (2,)")
    )
    cases.append(
        _gather_case(torch_module, c_module, torch_call, "float32", [7.0], (), 0,
                     [0], (), note="0-d self with a 0-d index -> 0-d")
    )
    cases.append(
        _gather_case(torch_module, c_module, torch_call, "float32", [1.0, 2.0], (2,), 0,
                     [1], (), note="1-d self with a 0-d index -> 0-d")
    )
    cases.append(
        _gather_case(torch_module, c_module, torch_call, "float32", [7.0], (), 0,
                     [0], (1, 1), expect="both_error",
                     note="0-d self with a 2-d index IS refused -- max(rank,1) is 1, not 2")
    )

    # The refusals, one per disagreement with candle's own gather.
    for idx_dtype in ["uint8", "int16", "float32"]:
        cases.append(
            _gather_case(torch_module, c_module, torch_call, "float32", flat, shape,
                         1, [0, 1], (1, 2), idx_dtype=idx_dtype, expect="both_error",
                         note="torch: 'gather(): Expected dtype int32/int64 for index'. candle's "
                              "own gather accepts u8/u32 -- a uint8 mask would be read as positions")
        )
    cases.append(
        _gather_case(torch_module, c_module, torch_call, "float32", flat, shape,
                     1, [0, 3], (1, 2), expect="both_error",
                     note="index past the axis extent")
    )
    cases.append(
        _gather_case(torch_module, c_module, torch_call, "float32", flat, shape,
                     1, [0, -1], (1, 2), expect="both_error",
                     note="gather does NOT take negative indices, unlike select/slice. candle's "
                          "i64 path would reach as_usize() and name a huge number instead of -1")
    )
    cases.append(
        _gather_case(torch_module, c_module, torch_call, "float32", flat, shape,
                     1, [0, 1], (2,), expect="both_error",
                     note="index rank must match self rank")
    )
    cases.append(
        _gather_case(torch_module, c_module, torch_call, "float32", flat, shape,
                     1, [0, 0, 0], (3, 1), expect="both_error",
                     note="index LARGER than self off-axis is refused (the mirror of the "
                          "'smaller' case above, which is allowed)")
    )
    cases.append(
        _gather_case(torch_module, c_module, torch_call, "float32", flat, shape,
                     2, [0, 0, 0, 0], (2, 2), expect="both_error",
                     note="dim out of range")
    )
    cases.append(
        _gather_case(torch_module, c_module, torch_call, "float32", [], (2, 0), 1,
                     [0, 0], (2, 1), expect="both_error",
                     note="a zero-extent axis has no valid index at all")
    )

    # Non-contiguous self. candle's gather refuses this outright
    # (RequiresContiguous); torch answers. Built through `transpose.int` so the
    # non-contiguity is real on both sides rather than asserted.
    cases.append(
        Case(
            name="gather(non-contiguous self via transpose) [candle's own gather refuses this]",
            op=op,
            run_torch=lambda: torch_call(
                torch_module.ops.aten.transpose.int(
                    torch_module.tensor([float(i) for i in range(12)]).reshape(3, 4), 0, 1
                ),
                1,
                torch_module.tensor([[0, 2], [1, 0], [2, 1], [0, 0]]),
            ),
            run_c=lambda: c_module._aten_dispatch(
                op,
                c_module._aten_dispatch(
                    "aten.transpose.int",
                    c_module._tensor_from_flat([float(i) for i in range(12)], [3, 4],
                                               dtype=c_module.float32),
                    0, 1,
                ),
                1,
                c_module._tensor_from_flat([0, 2, 1, 0, 2, 1, 0, 0], [4, 2], dtype=c_module.int64),
            ),
            note="torch gathers from a transposed tensor without comment; candle's kernel "
                 "raises RequiresContiguous, which is why this shim reads the elements itself.",
        )
    )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # self/dim/index all by keyword (sparse_grad is already exercised by
    # keyword above, in `_gather_case`'s `kwargs={"sparse_grad": True}`).
    kw_s_t, kw_s_c = pair_from_flat(torch_module, c_module, flat, shape, "float32")
    kw_i_t, kw_i_c = pair_from_flat(torch_module, c_module, [0, 2, 1, 0], (2, 2), "int64")
    cases.append(
        Case(
            name="gather(self=/dim=/index= all by keyword)",
            op=op,
            run_torch=lambda: torch_call(self=kw_s_t, dim=1, index=kw_i_t),
            run_c=lambda: c_module._aten_dispatch(op, self=kw_s_c, dim=1, index=kw_i_c),
        )
    )
    return cases


# --- aten.zero_.default ------------------------------------------------------
#
# Not a spelling of `fill_(0)` -- a separate overload upstream, so a separate
# op here and a separate set of cases. Unlike `fill_` there is no overflow
# table to reuse: zero is exact in every dtype, so what is worth checking is
# the dtype tag surviving, the in-place identity, and the degenerate shapes.
#
# Where it fires was measured, and it is not the forward pass:
# `nn.LayerNorm(8)`'s *constructor* calls it once (the bias), the forward calls
# it never. See the kernel docstring.


def zero__cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.zero_.default"
    cases: list[Case] = []
    for dtype_name in dt.DEFAULT_DTYPES:
        a_t, a_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (2, 2), dtype_name)
        cases.append(
            Case(
                name=f"zero_(dtype={dtype_name})",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c),
                note="in-place: compares the mutated operand zero_ returns",
            )
        )
    cases.append(
        Case(
            name="zero_(dtype=bool) [False, not 0]",
            op=op,
            run_torch=lambda: torch_call(torch_module.tensor([[True, True], [False, True]])),
            run_c=lambda: c_module._aten_dispatch(
                op, c_module._tensor_from_flat([1, 1, 0, 1], [2, 2], dtype=c_module.bool)
            ),
            note="the bool tag must survive -- a shim that zeroed through uint8 would "
                 "return a uint8 tensor and the dtype check would catch it",
        )
    )
    for label, flat, shape in [
        ("0-d", [3.0], ()),
        ("empty", [], (0,)),
        ("nan/inf overwritten", [float("nan"), float("inf"), float("-inf")], (3,)),
    ]:
        a_t, a_c = pair_from_flat(torch_module, c_module, flat, shape, "float32")
        cases.append(
            Case(
                name=f"zero_({label})",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c),
                note=label,
            )
        )
    cases.extend(
        c for c in _view_write_cases(torch_module, c_module)
        if c.op == "aten.zero_.default"
    )
    return cases


# --- large-size GEMM cases ---------------------------------------------------
#
# docs/GPT2.md §7 left this open: the golden harness only ever multiplied
# matrices small enough that accumulation order could not matter, so "does the
# shim's GEMM agree with torch's at model scale" had never been asked here.
# These cases ask it. What they found is written up in docs/ARCH.md §4; the
# short version is that the answer is dtype-dependent and the *flat* tolerance
# in dtypes.py is the wrong instrument for a reduction of depth k.
#
# Why a flat atol cannot describe a GEMM. dtypes.py sizes its tolerances at
# "roughly one ULP at magnitude ~1" -- by its own docstring. A dot product of
# length k does not produce a magnitude-1 answer from magnitude-1 inputs; it
# produces one of magnitude ~sqrt(k), and the standard forward error bound for
# a floating-point dot product is proportional to k*u*sum|a_i*b_i|, i.e. it
# grows with BOTH the depth and the output's own scale. Comparing that against
# a constant is a category error: it will pass a large tensor whose every
# element is wrong by a relative 1e-3 (if the elements are small) and fail a
# correct one (if they are large).
#
# So these cases carry their own checker, which asserts
#
#     max|torch - c|  <=  C * u(accumulate) * sqrt(k) * max|torch|
#                          + 1 ulp of the STORAGE dtype at that magnitude
#
# with C = 4 for headroom. Three things about that formula are load-bearing:
#
#   * `sqrt(k)`, not `k`. The textbook forward bound for a length-k dot product
#     is linear in k because it assumes every rounding error has the same sign.
#     They do not, and a linear bound is loose enough to pass an actively wrong
#     kernel. sqrt(k) is the statistical growth and still holds with margin at
#     every size measured (docs/ARCH.md §4 tabulates them).
#
#   * `u(accumulate)`, not `u(storage)`. **torch's CPU GEMM accumulates in
#     float32 no matter what the tensors are stored as** -- `at::opmath_type`.
#     That is measured, not assumed: `mm(half a, half b)` is *bitwise* equal to
#     `half(mm(float(a), float(b)))` at k = 4, 64 and 512, and the same for bmm
#     and addmm. Sizing a float16 GEMM's tolerance by float16's own unit
#     roundoff (4.9e-4) would let a kernel that accumulates in float16 pass
#     with 20x room to spare -- which is precisely the bug this checker was
#     rewritten to catch, after it did exactly that on the first attempt.
#
#   * the trailing ulp term. torch rounds once, at the end. A shim that also
#     accumulates in float32 lands within that single rounding, so the term is
#     what makes "match torch's method" the passing condition rather than
#     "be lucky".
#
# It is NOT a widened tolerance. At every size measured it is between 5x and
# 20x tighter than the answer, and it *fails* on an accumulation-dtype
# mismatch by a factor of 4.4 -- see docs/ARCH.md §4.
#
# The checker also re-derives what the default flat-tolerance pipeline would
# have said, so a verbose run prints both verdicts side by side and nobody has
# to take this note's word for it.

_GEMM_UNIT_ROUNDOFF = {
    "float64": 2.0 ** -53,
    "float32": 2.0 ** -24,
    "float16": 2.0 ** -11,
    "bfloat16": 2.0 ** -8,
}
# What torch accumulates a GEMM of this storage dtype in (`at::opmath_type`).
_GEMM_ACCUMULATE_IN = {
    "float64": "float64",
    "float32": "float32",
    "float16": "float32",
    "bfloat16": "float32",
}
_GEMM_ERROR_CONSTANT = 4.0


def _gemm_lcg(n: int, seed: int) -> list[float]:
    """White noise in [-1, 1), identical on both sides because both sides are
    handed this same list. Deliberately not `random` -- a golden case that
    changes its inputs between runs cannot be bisected."""
    out: list[float] = []
    x = seed
    for _ in range(n):
        x = (1103515245 * x + 12345) % (1 << 31)
        out.append((x / (1 << 30)) - 1.0)
    return out


def _gemm_scale_check(dtype_name: str, k: int):
    """A value_check for a GEMM of reduction depth `k`. Replaces the whole
    default pipeline, so it has to check dtype and shape itself."""
    tol = dt.tolerance_for(dtype_name)
    u_acc = _GEMM_UNIT_ROUNDOFF[_GEMM_ACCUMULATE_IN[dtype_name]]
    u_out = _GEMM_UNIT_ROUNDOFF[dtype_name]
    # C*u_acc*sqrt(k) for the accumulation, + 2*u_out for the single final
    # rounding into the storage dtype (2u is one ulp; u is half of one).
    bound_factor = _GEMM_ERROR_CONSTANT * u_acc * math.sqrt(k) + 2.0 * u_out

    def check(t_res, c_res) -> tuple[bool, str]:
        t_name, c_name = dt.dtype_name(t_res.dtype), dt.dtype_name(c_res.dtype)
        if t_name != c_name:
            return False, f"dtype mismatch: torch={t_name} c={c_name}"
        t_shape = tuple(int(x) for x in t_res.shape)
        c_shape = tuple(int(x) for x in c_res.shape)
        if t_shape != c_shape:
            return False, f"shape mismatch: torch={t_shape} c={c_shape}"

        def flatten(v):
            if isinstance(v, list):
                out = []
                for item in v:
                    out.extend(flatten(item))
                return out
            return [v]

        tv, cv = flatten(t_res.tolist()), flatten(c_res.tolist())
        scale = max((abs(v) for v in tv), default=0.0)
        max_abs = 0.0
        max_rel = 0.0
        flat_tol_failures = 0
        for x, y in zip(tv, cv):
            d = abs(x - y)
            if d > max_abs:
                max_abs = d
            if x != 0.0 and d / abs(x) > max_rel:
                max_rel = d / abs(x)
            if not math.isclose(x, y, rel_tol=tol.rtol, abs_tol=tol.atol):
                flat_tol_failures += 1
        bound = bound_factor * scale
        flat_verdict = (
            "would also pass" if flat_tol_failures == 0
            else f"would FAIL on {flat_tol_failures}/{len(tv)} elements"
        )
        detail = (
            f"k={k} n={len(tv)} max|d|={max_abs:.4g} max_rel={max_rel:.4g} "
            f"|out|max={scale:.4g} bound={bound:.4g} "
            f"(={_GEMM_ERROR_CONSTANT:g}*u[{_GEMM_ACCUMULATE_IN[dtype_name]}]"
            f"*sqrt(k)+2*u[{dtype_name}], scaled by |out|max); "
            f"flat atol={tol.atol:g}/rtol={tol.rtol:g} {flat_verdict}"
        )
        if max_abs > bound:
            return False, (
                "GEMM error exceeds the scale-aware bound -- this is an accumulation "
                f"difference, not rounding: {detail}"
            )
        return True, detail

    return check


def _big_gemm_case(torch_module, c_module, torch_call, op, dtype_name, m, k, n,
                   with_bias=False, batch=None, note="") -> Case:
    """One large mm / bmm / addmm case, checked against the scale-aware bound."""
    b = batch or 1
    a_flat = _gemm_lcg(b * m * k, 1)
    w_flat = _gemm_lcg(b * k * n, 2)
    a_shape = (b, m, k) if batch else (m, k)
    w_shape = (b, k, n) if batch else (k, n)
    a_t, a_c = pair_from_flat(torch_module, c_module, a_flat, a_shape, dtype_name)
    w_t, w_c = pair_from_flat(torch_module, c_module, w_flat, w_shape, dtype_name)
    if with_bias:
        bias_flat = _gemm_lcg(n, 3)
        bias_t, bias_c = pair_from_flat(torch_module, c_module, bias_flat, (n,), dtype_name)
        run_torch = lambda: torch_call(bias_t, a_t, w_t)  # noqa: E731
        run_c = lambda: c_module._aten_dispatch(op, bias_c, a_c, w_c)  # noqa: E731
    else:
        run_torch = lambda: torch_call(a_t, w_t)  # noqa: E731
        run_c = lambda: c_module._aten_dispatch(op, a_c, w_c)  # noqa: E731
    short = op.split(".", 2)[1]
    return Case(
        name=f"{short}(dtype={dtype_name}, {a_shape}x{w_shape}) [model-scale, k={k}: {note}]",
        op=op,
        run_torch=run_torch,
        run_c=run_c,
        note=note,
        value_check=_gemm_scale_check(dtype_name, k),
    )


# --- the four ops falcon/gptj/bloom/mpt all ask for, plus stack and relu -----
#
# docs/ARCH.md measured 32 architectures and found the largest single cluster in
# the tail: `falcon`, `gptj`, `bloom` and `mpt` are missing *exactly* the same
# four ops -- `le.Tensor`, `scalar_tensor.default`, `where.self` and
# `permute.default`. All four are the same idiom, and re-tracing the four models
# shows it end to end (docs/OPS4.md §1):
#
#     mask   = arange(...) <= arange(...)          aten.le.Tensor      (int64)
#     fill   = scalar_tensor(finfo(dtype).min)     aten.scalar_tensor  (0-d f32)
#     scores = where(mask, fill, scores)           aten.where.self
#     q/k/v  = permute(x, [0, 2, 1, 3])            aten.permute.default
#
# `stack.default` (gptj, cohere, helium, mamba) and `relu.default` (opt,
# nemotron, persimmon) ride along as the next two by architecture count.
#
# Every case below builds its tensors *inside* the lambdas, for the reason the
# note above `_pair` gives: a builder must not be able to crash the whole run at
# case-list time.


def _scalar_tensor_case(torch_module, c_module, torch_call, value, dtype_name=None,
                        kwargs=None, expect="match", note="") -> Case:
    op = "aten.scalar_tensor.default"
    kwargs = kwargs or {}

    def t_kw():
        out = dict(kwargs)
        if dtype_name is not None:
            out["dtype"] = dt.torch_dtype(torch_module, dtype_name)
        return out

    def c_kw():
        out = dict(kwargs)
        if dtype_name is not None:
            out["dtype"] = dt.c_dtype(c_module, dtype_name)
        return out

    extra = "".join(f", {k}={v!r}" for k, v in kwargs.items())
    return Case(
        name=f"scalar_tensor({value!r}, dtype={dtype_name or 'inferred'}{extra}) [{note}]",
        op=op,
        run_torch=lambda: torch_call(value, **t_kw()),
        run_c=lambda: c_module._aten_dispatch(op, value, **c_kw()),
        expect=expect,
        note=note,
    )


def scalar_tensor_cases(torch_module, c_module, torch_call) -> list[Case]:
    cases: list[Case] = []

    # The rule that would have been got wrong by copying `full`: the fill
    # value's category is *ignored*. `full([], 3)` is int64 and `full([], True)`
    # is bool, but `scalar_tensor` of either is float32 (measured). These four
    # cases are the whole difference and they are the reason the op has its own
    # kernel rather than a route into `full_default`.
    for value, note in [
        (1.5, "python float -> the default float, as expected"),
        (3, "python INT -> float32, NOT int64 -- `full([], 3)` would be int64"),
        (True, "python BOOL -> float32, NOT bool -- `full([], True)` would be bool"),
        (-2, "negative int, same rule"),
        (0.0, "zero is not a special case"),
        (float("nan"), "nan survives into the default float"),
        (float("inf"), "inf survives into the default float"),
    ]:
        cases.append(_scalar_tensor_case(torch_module, c_module, torch_call, value, note=note))

    # Every storable dtype, from each of the three scalar categories, since the
    # inference rule above means the category can only show up through the
    # conversion and never through the result dtype.
    for dtype_name in ["float64", "float32", "float16", "bfloat16",
                       "int64", "int32", "int16", "uint8", "bool"]:
        for value in [3, 1.5, True]:
            cases.append(
                _scalar_tensor_case(
                    torch_module, c_module, torch_call, value, dtype_name,
                    note="explicit dtype -- the conversion, not the inference",
                )
            )

    # `checked_convert` at numel == 1, which is where upstream's own fast-path
    # hole lives. The float16/bfloat16 rows must NOT raise and the float32 one
    # must -- getting that backwards is the failure this pins.
    for value, dtype_name, note in [
        (1e6, "float16", "OVERFLOWS float16 and is NOT refused: numel==1 takes upstream's "
                         "unchecked fast path and saturates to inf (`full([3], 1e6, float16)` raises)"),
        (1e300, "bfloat16", "same hole, bfloat16"),
        (1e300, "float32", "float32 is NOT in the hole -- upstream checks it even at one element"),
        (2 ** 40, "int32", "integer overflow is refused at any numel"),
        (-1, "uint8", "negative into unsigned WRAPS to 255 -- allowed, magnitude fits"),
        (300, "uint8", "magnitude does not fit -- refused"),
        (-1.5, "int64", "float into int TRUNCATES toward zero, giving -1 (not -2)"),
        (float("nan"), "int64", "int64 has no nan -- refused"),
        (float("inf"), "int64", "int64 has no inf -- refused"),
        (float("inf"), "float16", "float16 does have inf -- not an overflow"),
        (2, "bool", "any nonzero is True; bool never overflows"),
        (0.0, "bool", "zero is False"),
    ]:
        cases.append(
            _scalar_tensor_case(torch_module, c_module, torch_call, value, dtype_name, note=note)
        )

    # The factory keyword arguments. `layout=torch.strided` is passed
    # *explicitly* by bloom, mpt and gptj at this call site (measured), so it
    # has to be accepted rather than refused -- see `reject_layout`.
    cases.append(
        _scalar_tensor_case(
            torch_module, c_module, torch_call, 2.5, "float32",
            kwargs={"device": "cpu"}, note="device given as a string",
        )
    )
    cases.append(
        Case(
            name="scalar_tensor(2.5, layout=torch.strided) [the real call sites pass this]",
            op="aten.scalar_tensor.default",
            run_torch=lambda: torch_call(2.5, layout=torch_module.strided),
            run_c=lambda: c_module._aten_dispatch(
                "aten.scalar_tensor.default", 2.5, layout=torch_module.strided
            ),
            note="bloom/mpt/gptj send layout=torch.strided; it names the only layout "
                 "the shim has, so refusing it would block them on nothing",
        )
    )
    cases.append(
        Case(
            name="scalar_tensor(2.5, layout=torch.sparse_coo) [any other layout still refuses]",
            op="aten.scalar_tensor.default",
            run_torch=lambda: torch_call(2.5, layout=torch_module.sparse_coo),
            run_c=lambda: c_module._aten_dispatch(
                "aten.scalar_tensor.default", 2.5, layout=torch_module.sparse_coo
            ),
            expect="c_error",
            note="torch answers a dense tensor and ignores the request at this size; the "
                 "shim has no sparse layout and says so rather than silently answering dense",
        )
    )
    # The exact call the four architectures make.
    cases.append(
        Case(
            name="scalar_tensor(finfo(float32).min, dtype=float32) [the mask fill value, verbatim]",
            op="aten.scalar_tensor.default",
            run_torch=lambda: torch_call(
                torch_module.finfo(torch_module.float32).min, dtype=torch_module.float32
            ),
            run_c=lambda: c_module._aten_dispatch(
                "aten.scalar_tensor.default",
                torch_module.finfo(torch_module.float32).min,
                dtype=c_module.float32,
            ),
            note="falcon/gptj/bloom/mpt all build their attention mask fill this way",
        )
    )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1): `s`
    # (the fill value) by keyword -- `device`/`layout` are already exercised
    # by keyword above.
    cases.append(
        Case(
            name="scalar_tensor(s=/dtype= both by keyword)",
            op="aten.scalar_tensor.default",
            run_torch=lambda: torch_call(s=2.5, dtype=torch_module.float32),
            run_c=lambda: c_module._aten_dispatch("aten.scalar_tensor.default", s=2.5, dtype=c_module.float32),
        )
    )
    return cases


# --- aten.where.self ---------------------------------------------------------


def _where_case(torch_module, c_module, torch_call, cond, lhs, rhs,
                expect="match", note="") -> Case:
    """`cond`/`lhs`/`rhs` are `(flat, shape, dtype_name)` triples, built inside
    the lambdas."""
    op = "aten.where.self"

    def build(index):
        return tuple(
            _pair(torch_module, c_module, flat, shape, dtype_name)[index]
            for flat, shape, dtype_name in (cond, lhs, rhs)
        )

    return Case(
        name=f"where(cond={cond[1]}/{cond[2]}, self={lhs[1]}/{lhs[2]}, "
             f"other={rhs[1]}/{rhs[2]}) [{note}]",
        op=op,
        run_torch=lambda: torch_call(*build(0)),
        run_c=lambda: c_module._aten_dispatch(op, *build(1)),
        expect=expect,
        note=note,
    )


def where_self_cases(torch_module, c_module, torch_call) -> list[Case]:
    cases: list[Case] = []
    mask4 = ([1, 0, 1, 0], (4,), "bool")

    # Both branches in every storable dtype. `where` moves elements rather than
    # computing on them, so unlike `mm` there is no kernel-coverage split.
    for dtype_name in ["float64", "float32", "float16", "bfloat16",
                       "int64", "int32", "int16", "uint8", "bool"]:
        cases.append(
            _where_case(
                torch_module, c_module, torch_call, mask4,
                ([1, 2, 3, 4], (4,), dtype_name), ([9, 8, 7, 6], (4,), dtype_name),
                note="elementwise select, matched dtypes",
            )
        )

    # The shape rules. The third is the one a condition-shaped implementation
    # gets wrong: the result is the join of all THREE, not the condition's.
    for cond, lhs, rhs, note in [
        (([1, 0, 0, 1], (2, 2), "bool"), ([1.0], (), "float32"), ([-1.0], (), "float32"),
         "0-D BRANCHES broadcast up to the mask -- exactly what the four architectures do"),
        (([1], (), "bool"), ([float(i) for i in range(6)], (2, 3), "float32"),
         ([0.0, 0.0, 0.0], (3,), "float32"),
         "0-D CONDITION: result is (2,3), the join of all three, not the condition's ()"),
        (([1, 0], (2, 1), "bool"), ([1.0, 2.0, 3.0], (1, 3), "float32"), ([0.0], (1, 1), "float32"),
         "all three broadcast against each other"),
        (([1], (), "bool"), ([1.0], (), "float32"), ([2.0], (), "float32"),
         "everything 0-D -> a 0-D result"),
        (([], (0,), "bool"), ([], (0,), "float32"), ([], (0,), "float32"),
         "empty in, empty out -- not an error"),
        (([1, 0, 1], (3,), "bool"), ([1.0, 2.0], (2,), "float32"), ([0.0, 0.0], (2,), "float32"),
         "shapes that do not broadcast are refused by both"),
    ]:
        cases.append(
            _where_case(torch_module, c_module, torch_call, cond, lhs, rhs,
                        expect="both_error" if "refused" in note else "match", note=note)
        )

    # The condition's dtype. `uint8` is ACCEPTED here (deprecated upstream but
    # answered), which is the opposite of `masked_fill`'s rule -- copying that
    # refusal over would have refused a call torch answers.
    cases.append(
        _where_case(
            torch_module, c_module, torch_call, ([2, 0, 5, 0], (4,), "uint8"),
            ([1.0, 2.0, 3.0, 4.0], (4,), "float32"), ([-1.0, -2.0, -3.0, -4.0], (4,), "float32"),
            note="uint8 condition is ACCEPTED (deprecated upstream, still answered) and read "
                 "as truthiness -- 2 and 5 both select the first branch",
        )
    )
    for cond_dtype in ["int64", "int32", "float32"]:
        cases.append(
            _where_case(
                torch_module, c_module, torch_call, ([1, 0, 1, 0], (4,), cond_dtype),
                ([1.0, 2.0, 3.0, 4.0], (4,), "float32"), ([0.0, 0.0, 0.0, 0.0], (4,), "float32"),
                expect="both_error",
                note=f"a {cond_dtype} condition is refused -- only bool and (deprecated) uint8",
            )
        )

    # Values that a blend rather than a select would get wrong.
    cases.append(
        _where_case(
            torch_module, c_module, torch_call, ([1, 0], (2,), "bool"),
            ([float("nan"), 1.0], (2,), "float32"), ([2.0, float("inf")], (2,), "float32"),
            note="nan and inf are selected, not arithmetic -- the result is [nan, inf]",
        )
    )
    cases.append(
        _where_case(
            torch_module, c_module, torch_call, ([1], (1,), "bool"),
            ([1.0], (1,), "float32"), ([float("nan")], (1,), "float32"),
            note="the UNSELECTED branch is never read for its value: nan there is not "
                 "contagious (measured upstream)",
        )
    )

    # The gap: upstream promotes, this shim refuses. The full 9x9 table is in
    # docs/OPS4.md §2; these are the four rows that would be got wrong by
    # assuming "the wider one wins" (an integral branch never widens a floating
    # one, and float16 with bfloat16 escapes to float32).
    for lhs_dtype, rhs_dtype, upstream, note in [
        ("float32", "float64", "float64", "the ordinary widening"),
        ("float16", "int64", "float16", "an INTEGRAL branch does not widen a floating one"),
        ("float16", "bfloat16", "float32", "two reduced floats promote OUT to float32"),
        ("bool", "int64", "int64", "bool is the bottom of the lattice"),
    ]:
        cases.append(
            _where_case(
                torch_module, c_module, torch_call, mask4,
                ([1, 2, 3, 4], (4,), lhs_dtype), ([9, 8, 7, 6], (4,), rhs_dtype),
                expect="c_error",
                note=f"upstream promotes to {upstream} ({note}); the shim refuses rather than "
                     "guessing a promotion -- see same_dtype in rust/torch_c/src/aten.rs",
            )
        )

    # The idiom itself, at the shape falcon/gptj/bloom/mpt actually produce.
    cases.append(
        _where_case(
            torch_module, c_module, torch_call,
            ([1, 0, 0, 0, 1, 1, 0, 0, 1, 1, 1, 0, 1, 1, 1, 1], (1, 1, 4, 4), "bool"),
            ([0.0], (), "float32"), ([-3.4028234663852886e38], (), "float32"),
            note="the causal-mask idiom verbatim: a (1,1,S,S) bool mask selecting between "
                 "two 0-D scalar_tensor results",
        )
    )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # condition/self/other all by keyword.
    kw_cond_t, kw_cond_c = _pair(torch_module, c_module, [1, 0, 1, 0], (4,), "bool")
    kw_s_t, kw_s_c = _pair(torch_module, c_module, [1.0, 2.0, 3.0, 4.0], (4,), "float32")
    kw_o_t, kw_o_c = _pair(torch_module, c_module, [10.0, 20.0, 30.0, 40.0], (4,), "float32")
    cases.append(
        Case(
            name="where(condition=/self=/other= all by keyword)",
            op="aten.where.self",
            run_torch=lambda: torch_call(condition=kw_cond_t, self=kw_s_t, other=kw_o_t),
            run_c=lambda: c_module._aten_dispatch(
                "aten.where.self", condition=kw_cond_c, self=kw_s_c, other=kw_o_c
            ),
        )
    )
    return cases


# --- aten.where.ScalarOther --------------------------------------------------
#
# `torch.where(mask, tensor, python_scalar)`. transformers' `eager_mask`
# reaches it verbatim -- `masking_utils.py:603` is
#
#     mask = torch.where(mask, torch.tensor(0.0, device=..., dtype=dtype), min_dtype)
#
# with `min_dtype = torch.finfo(dtype).min`, a Python float. It was the one
# op standing between this shim and a real pretrained model's EAGER forward
# (docs/CKPT2.md §7.1).
#
# What the overload does was measured, not read off the schema. A
# `TorchDispatchMode` over the call above reports
#
#     aten.scalar_tensor.default(-3.5, dtype=<PROMOTED dtype>)
#     aten.where.self(cond, self, that)
#
# -- the scalar becomes a 0-D tensor *at the promoted dtype*, and then it is
# ordinary `where.self` with matched branches. The kernel does the same two
# steps rather than growing a third select path.
#
# The promotion is torch's "wrapped number" rule and every cell below was
# measured on 2.13.0. Three of them break a plausible-looking shortcut:
#
#   float16 tensor + FLOAT scalar   -> float16, not float32. A Python float
#                                      does not widen a float tensor.
#   int64 tensor + FLOAT scalar     -> float32 (the DEFAULT float), not
#                                      float64 and not int64.
#   bool tensor + `True`            -> bool, but bool tensor + `1` -> int64.
#                                      Same numeric value, different Python
#                                      TYPE, different answer -- which is why
#                                      the kernel inspects the raw object for
#                                      `PyBool` instead of reading the shim's
#                                      `Scalar`, whose `Int`/`Float` split
#                                      folds `bool` into `Int`.

# (tensor dtype, scalar, upstream result dtype). Measured.
_WHERE_SCALAR_OTHER_PROMOTION = [
    ("bool", True, "bool"),
    ("bool", False, "bool"),
    ("bool", 1, "int64"),
    ("bool", 3, "int64"),
    ("bool", 2.5, "float32"),
    ("uint8", True, "uint8"),
    ("uint8", 7, "uint8"),
    ("uint8", 2.5, "float32"),
    ("int16", 7, "int16"),
    ("int16", 2.5, "float32"),
    ("int32", 7, "int32"),
    ("int32", 2.5, "float32"),
    ("int64", True, "int64"),
    ("int64", 7, "int64"),
    ("int64", 2.5, "float32"),
    ("float16", True, "float16"),
    ("float16", 7, "float16"),
    ("float16", 2.5, "float16"),
    ("bfloat16", 7, "bfloat16"),
    ("bfloat16", 2.5, "bfloat16"),
    ("float32", 7, "float32"),
    ("float32", 2.5, "float32"),
    ("float64", 7, "float64"),
    ("float64", 2.5, "float64"),
]


def _where_scalar_other_case(torch_module, c_module, torch_call, cond, self_, scalar,
                             expect="match", note="") -> Case:
    """`cond`/`self_` are `(flat, shape, dtype_name)` triples; `scalar` is a
    plain Python number and is passed through untouched, because its Python
    type is part of what the op reads."""
    op = "aten.where.ScalarOther"

    def build(index):
        return tuple(
            _pair(torch_module, c_module, flat, shape, dtype_name)[index]
            for flat, shape, dtype_name in (cond, self_)
        )

    return Case(
        name=f"where.ScalarOther(cond={cond[1]}/{cond[2]}, self={self_[1]}/{self_[2]}, "
             f"other={scalar!r}:{type(scalar).__name__}) [{note}]",
        op=op,
        run_torch=lambda: torch_call(*build(0), scalar),
        run_c=lambda: c_module._aten_dispatch(op, *build(1), scalar),
        expect=expect,
        note=note,
    )


def where_scalar_other_cases(torch_module, c_module, torch_call) -> list[Case]:
    cases: list[Case] = []
    mask4 = ([1, 0, 1, 0], (4,), "bool")

    for dtype_name, scalar, upstream in _WHERE_SCALAR_OTHER_PROMOTION:
        flat = [1, 0, 1, 1] if dtype_name == "bool" else [1, 2, 3, 4]
        cases.append(
            _where_scalar_other_case(
                torch_module, c_module, torch_call, mask4, (flat, (4,), dtype_name), scalar,
                note=f"{dtype_name} tensor with a {type(scalar).__name__} scalar "
                     f"-> {upstream}",
            )
        )

    # The idiom itself, at both dtypes SmolLM2-135M can arrive in. `finfo.min`
    # is the actual argument `eager_mask` passes and it sits exactly ON the
    # dtype's boundary, which is where an overflow check written with `>=`
    # instead of `>` would refuse a call upstream answers.
    for dtype_name, min_value in [
        ("float32", -3.4028234663852886e38),
        ("bfloat16", -3.3895313892515355e38),
    ]:
        cases.append(
            _where_scalar_other_case(
                torch_module, c_module, torch_call,
                ([1, 0, 0, 0, 1, 1, 0, 0, 1, 1, 1, 0, 1, 1, 1, 1], (1, 1, 4, 4), "bool"),
                ([0.0], (), dtype_name), min_value,
                note="masking_utils.py:603 verbatim -- a (1,1,S,S) bool mask, a 0-D 0.0, "
                     "and finfo(dtype).min ON the dtype boundary",
            )
        )

    # Shapes. The 0-D `self` above already covers the branch carrying no
    # shape; these cover the other direction and the empty case.
    for self_, note in [
        (([1.0, 2.0, 3.0, 4.0], (2, 2), "float32"), "self shaped, cond shaped, equal"),
        (([], (0,), "float32"), "empty in, empty out -- not an error"),
    ]:
        cond = ([1, 0, 1, 0], (2, 2), "bool") if self_[1] == (2, 2) else ([], (0,), "bool")
        cases.append(
            _where_scalar_other_case(
                torch_module, c_module, torch_call, cond, self_, -1.0, note=note
            )
        )
    cases.append(
        _where_scalar_other_case(
            torch_module, c_module, torch_call,
            ([1, 0, 1], (3,), "bool"), ([1.0, 2.0], (2,), "float32"), 0.0,
            expect="both_error", note="shapes that do not broadcast are refused by both",
        )
    )

    # The condition's dtype rule is `where.self`'s, re-measured here rather
    # than inherited: `uint8` is answered (with a deprecation warning
    # upstream), everything else non-bool is refused.
    cases.append(
        _where_scalar_other_case(
            torch_module, c_module, torch_call, ([2, 0, 5, 0], (4,), "uint8"),
            ([1.0, 2.0, 3.0, 4.0], (4,), "float32"), 3.0,
            note="uint8 condition is ACCEPTED and read as truthiness, same as where.self",
        )
    )
    for cond_dtype in ["int64", "float32"]:
        cases.append(
            _where_scalar_other_case(
                torch_module, c_module, torch_call, ([1, 0, 1, 0], (4,), cond_dtype),
                ([1.0, 2.0, 3.0, 4.0], (4,), "float32"), 0.0, expect="both_error",
                note=f"a {cond_dtype} condition is refused -- only bool and (deprecated) uint8",
            )
        )

    # A scalar that does not fit the promoted dtype. Upstream converts through
    # the same checked path `scalar_tensor` uses, so the two answers have to
    # agree on BOTH sides of the boundary -- `-1` into `uint8` wraps to 255
    # and is answered, `300` overflows and is refused.
    cases.append(
        _where_scalar_other_case(
            torch_module, c_module, torch_call, mask4, ([1, 2, 3, 4], (4,), "uint8"), -1,
            note="-1 into uint8 WRAPS to 255 and is answered (two's complement allowance)",
        )
    )
    cases.append(
        _where_scalar_other_case(
            torch_module, c_module, torch_call, mask4, ([1, 2, 3, 4], (4,), "uint8"), 300,
            expect="both_error",
            note="300 does not fit uint8: 'value cannot be converted to type uint8_t "
                 "without overflow' on both sides",
        )
    )
    cases.append(
        _where_scalar_other_case(
            torch_module, c_module, torch_call, mask4, ([1, 2, 3, 4], (4,), "int16"), 2 ** 40,
            expect="both_error", note="2**40 does not fit int16 -- refused by both",
        )
    )

    # The unselected branch is never read for its value: `nan` in the scalar
    # position is not contagious when the condition is all-true. Same property
    # `where.self` pins, re-measured for this overload.
    cases.append(
        _where_scalar_other_case(
            torch_module, c_module, torch_call, ([1, 1], (2,), "bool"),
            ([1.0, 2.0], (2,), "float32"), float("nan"),
            note="the UNSELECTED scalar branch is not contagious -- the result is [1., 2.]",
        )
    )
    cases.append(
        _where_scalar_other_case(
            torch_module, c_module, torch_call, ([0, 0], (2,), "bool"),
            ([1.0, 2.0], (2,), "float32"), float("-inf"),
            note="-inf IS selected when the condition is false -- selected, not blended",
        )
    )

    # `other` as a 0-D tensor. `scalar_arg` accepts one everywhere else in
    # this shim (torch takes a 0-D tensor wherever a `Scalar` is taken), but
    # this overload is the exception: upstream's own binding refuses it
    # ("aten::where() Expected a value of type 'number' for argument 'other'
    # but instead found type Tensor"), measured. Answering it would compute
    # where torch raises.
    def _tensor_other(index):
        cond_t = _pair(torch_module, c_module, [1, 0], (2,), "bool")[index]
        self_t = _pair(torch_module, c_module, [1.0, 2.0], (2,), "float32")[index]
        other_t = _pair(torch_module, c_module, [3.0], (), "float32")[index]
        return cond_t, self_t, other_t

    cases.append(
        Case(
            name="where.ScalarOther(other given as a 0-D TENSOR -- refused by both)",
            op="aten.where.ScalarOther",
            run_torch=lambda: torch_call(*_tensor_other(0)),
            run_c=lambda: c_module._aten_dispatch("aten.where.ScalarOther", *_tensor_other(1)),
            expect="both_error",
            note="upstream's binding wants a number here even though a 0-D tensor is a "
                 "Scalar everywhere else; the shim refuses for the same reason",
        )
    )
    return cases


# --- aten.permute.default ----------------------------------------------------


def _permute_case(torch_module, c_module, torch_call, flat, shape, dims,
                  dtype_name="float32", expect="match", note="") -> Case:
    op = "aten.permute.default"
    return Case(
        name=f"permute(dtype={dtype_name}, shape={shape}, dims={dims}) [{note}]",
        op=op,
        run_torch=lambda: torch_call(
            _pair(torch_module, c_module, flat, shape, dtype_name)[0], list(dims)
        ),
        run_c=lambda: c_module._aten_dispatch(
            op, _pair(torch_module, c_module, flat, shape, dtype_name)[1], list(dims)
        ),
        expect=expect,
        note=note,
    )


def permute_cases(torch_module, c_module, torch_call) -> list[Case]:
    six = [float(i) for i in range(6)]
    cases: list[Case] = []

    for dtype_name in ["float64", "float32", "float16", "bfloat16",
                       "int64", "int32", "int16", "uint8", "bool"]:
        values = [1, 0, 0, 1, 1, 0] if dtype_name == "bool" else six
        cases.append(
            _permute_case(torch_module, c_module, torch_call, values, (2, 3), [1, 0],
                          dtype_name, note="the 2-D transpose spelling, every dtype")
        )

    for flat, shape, dims, note in [
        (six, (2, 3), [0, 1], "the identity permutation is a legal no-op"),
        (six, (2, 3), [-1, -2], "negative entries normalise: [-1,-2] == [1,0]"),
        ([float(i) for i in range(24)], (2, 3, 4), [2, 0, 1], "3-D rotate -> (4,2,3)"),
        ([float(i) for i in range(24)], (2, 3, 4), [1, 2, 0], "3-D the other way -> (3,4,2)"),
        ([float(i) for i in range(24)], (1, 2, 3, 4), [0, 2, 1, 3],
         "the attention spelling all four architectures call"),
        ([7.0], (), [], "0-D takes an EMPTY dims list and comes back unchanged"),
        ([1.0, 2.0, 3.0], (3,), [0], "1-D identity"),
        ([], (0, 3), [1, 0], "an empty extent permutes to (3,0)"),
    ]:
        cases.append(
            _permute_case(torch_module, c_module, torch_call, flat, shape, dims, note=note)
        )

    # The refusals. The length rule is exact -- `rank.max(1)` would let the
    # 0-D/[0] case through, and upstream refuses it.
    for flat, shape, dims, note in [
        ([7.0], (), [0], "0-D with a 1-element dims list IS refused (rank is 0, not max(0,1))"),
        (six, (2, 3), [0], "too few dims"),
        (six, (2, 3), [0, 1, 2], "too many dims"),
        (six, (2, 3), [0, 0], "a duplicate dim is refused -- it is not a permutation"),
        (six, (2, 3), [2, 0], "out of range, positive"),
        (six, (2, 3), [-3, 0], "out of range, negative"),
    ]:
        cases.append(
            _permute_case(torch_module, c_module, torch_call, flat, shape, dims,
                          expect="both_error", note=note)
        )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # self/dims both by keyword.
    kw_t, kw_c = _pair(torch_module, c_module, six, (2, 3), "float32")
    cases.append(
        Case(
            name="permute(self=/dims= both by keyword)",
            op="aten.permute.default",
            run_torch=lambda: torch_call(self=kw_t, dims=[1, 0]),
            run_c=lambda: c_module._aten_dispatch("aten.permute.default", self=kw_c, dims=[1, 0]),
        )
    )
    return cases


# --- aten.stack.default ------------------------------------------------------


def _stack_case(torch_module, c_module, torch_call, entries, dim=None,
                expect="match", note="") -> Case:
    """`entries` is a list of `(flat, shape, dtype_name)` triples."""
    op = "aten.stack.default"
    args = () if dim is None else (dim,)

    def build(index):
        return [_pair(torch_module, c_module, f, s, d)[index] for f, s, d in entries]

    shapes = [e[1] for e in entries]
    dtypes = sorted({e[2] for e in entries})
    return Case(
        name=f"stack(n={len(entries)}, shapes={shapes}, dtypes={dtypes}, "
             f"dim={'default 0' if dim is None else dim}) [{note}]",
        op=op,
        run_torch=lambda: torch_call(build(0), *args),
        run_c=lambda: c_module._aten_dispatch(op, build(1), *args),
        expect=expect,
        note=note,
    )


def stack_cases(torch_module, c_module, torch_call) -> list[Case]:
    cases: list[Case] = []

    for dtype_name in ["float64", "float32", "float16", "bfloat16",
                       "int64", "int32", "int16", "uint8", "bool"]:
        a = ([1, 0] if dtype_name == "bool" else [1, 2], (2,), dtype_name)
        b = ([0, 1] if dtype_name == "bool" else [3, 4], (2,), dtype_name)
        cases.append(
            _stack_case(torch_module, c_module, torch_call, [a, b],
                        note="two 1-D entries on a new leading axis, every dtype")
        )

    a = ([1.0, 2.0], (2,), "float32")
    b = ([3.0, 4.0], (2,), "float32")
    # The dim rule, which is `unsqueeze`'s and NOT `cat`'s: the new axis may go
    # after the last existing one, so dim == rank is legal.
    for dim, note in [
        (0, "explicit dim 0 -> (2,2), rows are the entries"),
        (1, "dim == RANK is legal (cat would refuse it) -> (2,2), columns are the entries"),
        (-1, "-1 is the new last axis, same as dim=1 here"),
        (-2, "-2 is the new first axis, same as dim=0 here"),
    ]:
        cases.append(_stack_case(torch_module, c_module, torch_call, [a, b], dim, note=note))
    for dim in [2, -3]:
        cases.append(
            _stack_case(torch_module, c_module, torch_call, [a, b], dim, expect="both_error",
                        note=f"dim={dim} is outside [-(rank+1), rank]")
        )

    scalar_a = ([1.0], (), "float32")
    scalar_b = ([2.0], (), "float32")
    for entries, dim, expect, note in [
        ([a], None, "match", "a single entry still gets the new axis -> (1,2)"),
        ([a, b, a], 1, "match", "three entries, dim=1 -> (2,3)"),
        ([scalar_a, scalar_b], None, "match", "0-D entries stack into a 1-D result"),
        ([scalar_a, scalar_b], 1, "both_error", "0-D entries have no dim 1"),
        ([([], (0,), "float32"), ([], (0,), "float32")], None, "match",
         "empty entries give shape (2,0), not an error"),
        ([([float(i) for i in range(6)], (2, 3), "float32")] * 2, 1, "match",
         "2-D entries, new axis in the middle -> (2,2,3)"),
        ([([float(i) for i in range(8)], (1, 2, 2, 2), "float32")] * 2, -1, "match",
         "the gptj rotary spelling: two 4-D halves stacked on a new last axis"),
    ]:
        cases.append(
            _stack_case(torch_module, c_module, torch_call, entries, dim, expect=expect, note=note)
        )

    # The size rule, which is `stack`'s alone: `cat` lets the join axis differ,
    # `stack` requires every entry to be identical, rank included.
    cases.append(
        _stack_case(
            torch_module, c_module, torch_call,
            [a, ([1.0, 2.0, 3.0], (3,), "float32")], expect="both_error",
            note="differing extents are refused -- cat on dim 0 would accept these",
        )
    )
    cases.append(
        _stack_case(
            torch_module, c_module, torch_call,
            [a, ([1.0, 2.0], (2, 1), "float32")], expect="both_error",
            note="differing RANK is refused too, even at the same element count",
        )
    )
    cases.append(
        Case(
            name="stack([]) [an empty list has no shape to invent]",
            op="aten.stack.default",
            run_torch=lambda: torch_call([]),
            run_c=lambda: c_module._aten_dispatch("aten.stack.default", []),
            expect="both_error",
            note="upstream: 'stack expects a non-empty TensorList'",
        )
    )

    # The gap: upstream promotes here as well.
    for lhs_dtype, rhs_dtype, upstream in [
        ("float32", "float64", "float64"),
        ("int64", "float32", "float32"),
        ("bool", "int64", "int64"),
    ]:
        cases.append(
            _stack_case(
                torch_module, c_module, torch_call,
                [([1, 2], (2,), lhs_dtype), ([3, 4], (2,), rhs_dtype)],
                expect="c_error",
                note=f"upstream promotes the entries to {upstream}; the shim refuses, the same "
                     "way cat_default does",
            )
        )
    return cases


# --- aten.relu.default -------------------------------------------------------


def relu_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.relu.default"
    cases: list[Case] = []

    # relu has an integral CPU kernel upstream (silu does not), so the integral
    # dtypes belong here as matches rather than refusals.
    for dtype_name in ["float64", "float32", "float16", "bfloat16",
                       "int64", "int32", "int16"]:
        cases.append(
            _unary_case(torch_module, c_module, op, torch_call, dtype_name,
                        [-2, -1, 0, 1, 2], (5,), "negatives clamp, non-negatives pass through")
        )
    # uint8 with non-negative literals only: `torch.tensor(-1, uint8)` wraps to
    # 255 while `_C._tensor_from_flat` saturates to 0, a constructor difference
    # docs/GPT2.md §7 already recorded and which has nothing to do with relu.
    cases.append(
        _unary_case(torch_module, c_module, op, torch_call, "uint8",
                    [0, 1, 2, 255], (4,),
                    "on an unsigned dtype relu is the identity -- no element is negative")
    )
    cases.append(
        Case(
            name="relu(dtype=bool, shape=(2,)) [upstream refuses bool]",
            op=op,
            run_torch=lambda: torch_call(_pair(torch_module, c_module, [1, 0], (2,), "bool")[0]),
            run_c=lambda: c_module._aten_dispatch(
                op, _pair(torch_module, c_module, [1, 0], (2,), "bool")[1]
            ),
            expect="both_error",
            note="'Boolean inputs not supported for relu' -- a bool relu would be the identity, "
                 "and upstream would rather say no than answer it",
        )
    )

    # The two inputs that separate `x < 0 ? 0 : x` from `max(x, 0)`. A max-shaped
    # implementation passes everything above and fails exactly here.
    cases.append(
        Case(
            name="relu(float32, [nan, inf, -inf, -0.0, 0.0]) [NOT max(x,0)]",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module,
                      [float("nan"), float("inf"), float("-inf"), -0.0, 0.0], (5,), "float32")[0]
            ),
            run_c=lambda: c_module._aten_dispatch(
                op,
                _pair(torch_module, c_module,
                      [float("nan"), float("inf"), float("-inf"), -0.0, 0.0], (5,), "float32")[1],
            ),
            note="measured upstream: [nan, inf, 0.0, -0.0, 0.0]. nan SURVIVES (so this is not a "
                 "comparison-ordered maximum) and -0.0 keeps its sign (so this is not a clamp "
                 "that normalises) -- both fall out of `x < 0 ? 0 : x`",
        )
    )
    cases.append(
        Case(
            name="relu(float64, [nan, -0.0]) [the same two, at double precision]",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [float("nan"), -0.0], (2,), "float64")[0]
            ),
            run_c=lambda: c_module._aten_dispatch(
                op, _pair(torch_module, c_module, [float("nan"), -0.0], (2,), "float64")[1]
            ),
            note="not a float32-only accident",
        )
    )

    for flat, shape, note in [
        ([-3.0], (), "0-D input"),
        ([], (0,), "empty input"),
        ([float(i) - 3 for i in range(12)], (3, 4), "2-D, straddling zero"),
        ([-1e30, 1e30, -1e-30, 1e-30], (4,), "magnitudes far from 1"),
    ]:
        cases.append(
            _unary_case(torch_module, c_module, op, torch_call, "float32", flat, shape, note)
        )
    return cases


# --- aten.relu_.default ------------------------------------------------------
#
# `relu.default`'s in-place sibling -- `F.relu(x, inplace=True)` traces to
# this overload, not `relu.default` (docs/SPELLINGS.md §6.6 measured the
# kernel gap: zero hits before this). The value is `relu.default`'s
# unchanged; what's new here is the in-place contract, so the cases below
# follow `add__tensor_cases`'s shape (mutated-receiver comparisons) rather
# than re-deriving `relu_cases`' value coverage from scratch.


def relu__cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.relu_.default"
    cases: list[Case] = []

    for dtype_name in ["float64", "float32", "float16", "bfloat16",
                       "int64", "int32", "int16"]:
        dst_t, dst_c = pair_from_flat(torch_module, c_module, [-2, -1, 0, 1, 2], (5,), dtype_name)
        cases.append(
            Case(
                name=f"relu_(dtype={dtype_name}) [in-place: compares the mutated receiver]",
                op=op,
                run_torch=lambda dst_t=dst_t: torch_call(dst_t),
                run_c=lambda dst_c=dst_c: c_module._aten_dispatch(op, dst_c),
                note="negatives clamp, non-negatives pass through, same as relu.default",
            )
        )

    # uint8: identity, same reasoning `relu_cases` gives for the out-of-place
    # overload (no unsigned element is negative).
    dst_u8_t, dst_u8_c = pair_from_flat(torch_module, c_module, [0, 1, 2, 255], (4,), "uint8")
    cases.append(
        Case(
            name="relu_(dtype=uint8) [identity, in-place]",
            op=op,
            run_torch=lambda: torch_call(dst_u8_t),
            run_c=lambda: c_module._aten_dispatch(op, dst_u8_c),
            note="on an unsigned dtype relu_ is the identity -- no element is negative",
        )
    )

    # The two values that separate `x < 0 ? 0 : x` from `max(x, 0)`, re-hit
    # in-place -- measured on real torch to make sure the in-place overload
    # answers the same values relu.default does rather than assuming it.
    dst_special_t, dst_special_c = pair_from_flat(
        torch_module, c_module,
        [float("nan"), float("inf"), float("-inf"), -0.0, 0.0], (5,), "float32",
    )
    cases.append(
        Case(
            name="relu_(float32, [nan, inf, -inf, -0.0, 0.0]) [NOT max(x,0), in-place]",
            op=op,
            run_torch=lambda: torch_call(dst_special_t),
            run_c=lambda: c_module._aten_dispatch(op, dst_special_c),
            note="measured upstream: [nan, inf, 0.0, -0.0, 0.0] -- nan survives, -0.0 keeps its "
                 "sign, same as relu.default",
        )
    )

    bool_t, bool_c = pair_from_flat(torch_module, c_module, [1, 0], (2,), "bool")
    cases.append(
        Case(
            name="relu_(dtype=bool) [upstream refuses bool, in-place too]",
            op=op,
            run_torch=lambda: torch_call(bool_t),
            run_c=lambda: c_module._aten_dispatch(op, bool_c),
            expect="both_error",
            note="'Boolean inputs not supported for relu' -- same refusal wording as "
                 "relu.default, measured on the in-place overload too",
        )
    )
    cases.extend(relu__member_cases(torch_module, c_module))
    cases.extend(
        c for c in _view_write_cases(torch_module, c_module)
        if c.op == "aten.relu_.default"
    )
    return cases


# --- aten.le.Tensor ----------------------------------------------------------
#
# The Tensor-overload sibling of `le.Scalar`. It exists as its own key for the
# same reason `lt.Tensor`/`lt.Scalar` do -- different schemas -- and it is the
# op the four architectures build their causal mask with.


def le_tensor_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.le.Tensor"
    cases: list[Case] = []
    for dtype_name in _CMP_DTYPES:
        for sc in _CMP_SCENARIOS:
            cases.append(
                _binary_tensor_case(
                    torch_module, c_module, op, torch_call, dtype_name,
                    sc["a_flat"], sc["a_shape"], sc["b_flat"], sc["b_shape"], sc["note"],
                )
            )
    cases.append(
        Case(
            name="le(float32, nan <= nan) [every comparison against NaN is false, including <=]",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [float("nan"), 1.0], (2,), "float32")[0],
                _pair(torch_module, c_module, [float("nan"), 1.0], (2,), "float32")[0],
            ),
            run_c=lambda: c_module._aten_dispatch(
                op,
                _pair(torch_module, c_module, [float("nan"), 1.0], (2,), "float32")[1],
                _pair(torch_module, c_module, [float("nan"), 1.0], (2,), "float32")[1],
            ),
            note="nan <= nan is False even though the two sides are the same object; "
                 "1.0 <= 1.0 in the same call is True, so this is not a blanket False",
        )
    )
    cases.append(
        Case(
            name="le(int64, causal mask idiom) [arange(S)[None] <= arange(S)[:,None]]",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [0, 1, 2, 3], (1, 1, 1, 4), "int64")[0],
                _pair(torch_module, c_module, [0, 1, 2, 3], (1, 1, 4, 1), "int64")[0],
            ),
            run_c=lambda: c_module._aten_dispatch(
                op,
                _pair(torch_module, c_module, [0, 1, 2, 3], (1, 1, 1, 4), "int64")[1],
                _pair(torch_module, c_module, [0, 1, 2, 3], (1, 1, 4, 1), "int64")[1],
            ),
            note="the lower-triangular mask falcon/gptj/bloom/mpt all build, at the exact "
                 "(1,1,S,1) vs (1,1,1,S) broadcast they use",
        )
    )
    cases.append(
        Case(
            name="le(bool, [T,F] <= [F,T]) [False <= True, so bool ordering is False < True]",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [1, 0], (2,), "bool")[0],
                _pair(torch_module, c_module, [0, 1], (2,), "bool")[0],
            ),
            run_c=lambda: c_module._aten_dispatch(
                op,
                _pair(torch_module, c_module, [1, 0], (2,), "bool")[1],
                _pair(torch_module, c_module, [0, 1], (2,), "bool")[1],
            ),
            note="bool compares as 0/1, giving [False, True]",
        )
    )
    return cases


# --- the five ops docs/TAIL.md needed to open falcon/bloom/gpt_bigcode ------
#
# All five already had a kernel in rust/torch_c/src/aten.rs and showed up in
# `_aten_implemented()` before this file had a builder for any of them --
# `compare.py` was failing every one with `<no case builder registered>`.
# Each builder below re-measures the claims the kernel's own doc comment
# makes against torch 2.13.0 rather than trusting them, per this module's
# own rule (see the note above `_pair`): a doc comment is not a golden case.
#
# Two real, measured discrepancies came out of that re-measurement and are
# encoded as `expect="c_error"`/`"torch_error"` cases below rather than
# "fixed" (rust/torch_c/src/aten.rs is out of scope for this task):
#
#   * `aten.mul.Scalar(bool_tensor, scalar)` -- upstream computes this
#     *arithmetically* (`True`/`False` read as `1`/`0`, promoted exactly like
#     any other integral tensor: int scalar keeps int64, float scalar gives
#     float32). The shim's `arith_tag` refuses every bool tensor unconditionally,
#     which is right for the `.Tensor` overloads (upstream's bool `*` there
#     really is a logical and) but wrong for `.Scalar` -- `c_error`.
#   * `aten.add_.Tensor(bool_tensor, bool_tensor)` -- upstream computes this
#     too, as a logical or (`True`/`False` and `True`/`True` -> `[True, True]`,
#     measured). The shim's own doc comment above `add_inplace` claims this
#     "matches add.Tensor's own refusal", but that refusal is internal to the
#     shim, not upstream's -- upstream never refuses bool here. `c_error`.
#
# See docs/TAIL.md for the full measurement transcript and the exact
# `_aten_implemented()` counts this closed.


def _baddbmm_case(
    torch_module, c_module, torch_call, dtype_name,
    self_flat, self_shape, b1_flat, b1_shape, b2_flat, b2_shape,
    kwargs=None, expect="match", note="",
) -> Case:
    kwargs = kwargs or {}
    op = "aten.baddbmm.default"
    s_t, s_c = pair_from_flat(torch_module, c_module, self_flat, self_shape, dtype_name)
    a_t, a_c = pair_from_flat(torch_module, c_module, b1_flat, b1_shape, dtype_name)
    b_t, b_c = pair_from_flat(torch_module, c_module, b2_flat, b2_shape, dtype_name)
    return Case(
        name=f"baddbmm(dtype={dtype_name}, self={self_shape}, {b1_shape}x{b2_shape}, {kwargs}) [{note}]",
        op=op,
        run_torch=lambda: torch_call(s_t, a_t, b_t, **kwargs),
        run_c=lambda: c_module._aten_dispatch(op, s_c, a_c, b_c, **kwargs),
        expect=expect,
        note=note,
    )


# (2,2,3) @ (2,3,2) -> (2,2,2), batch of 2 -- big enough that a kernel
# dropping the batch dimension (bmm_cases' own concern) would show up here
# too. Product, worked by hand per batch:
#   batch0: [[1,2,3],[4,5,6]] @ [[1,0],[0,1],[1,0]] = [[4,2],[10,5]]... but
# with the actual b2 pattern used below the exact numbers are re-derived
# from beta=0/alpha=1 cases rather than transcribed here.
_BADDBMM_B1 = (list(range(1, 13)), (2, 2, 3))
_BADDBMM_B2 = ([1.0, 0.0, 0.0, 1.0, 0.0, 1.0, 1.0, 0.0, 1.0, 1.0, 0.0, 1.0], (2, 3, 2))
_BADDBMM_SELF = ([0.0] * 8, (2, 2, 2))


def baddbmm_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.baddbmm.default"
    cases: list[Case] = []

    scenarios = [
        (None, "plain: self + batch1 @ batch2"),
        (dict(beta=2, alpha=3), "integer beta/alpha"),
        (dict(beta=0.5, alpha=0.25), "fractional beta/alpha"),
        # The two quick returns, addmm's rule reused batched (kernel doc).
        (dict(beta=0), "beta=0 -- self dropped"),
        (dict(alpha=0), "alpha=0 -- product dropped"),
        (dict(beta=0, alpha=0), "both zero -- a shaped tensor of zeros, not an error"),
        (dict(beta=True), "beta as a bool, which torch reads as 1"),
        (dict(beta=False), "beta as a bool, which torch reads as 0"),
    ]
    for dtype_name in _MM_MATCH_DTYPES:
        for kwargs, note in scenarios:
            cases.append(
                _baddbmm_case(
                    torch_module, c_module, torch_call, dtype_name,
                    *_BADDBMM_SELF, *_BADDBMM_B1, *_BADDBMM_B2, kwargs=kwargs, note=note,
                )
            )
        # `self` broadcasting into the (batch, n, p) target -- measured
        # against real torch: 1-D, 0-d, 2-D (no batch dim), and a
        # singleton-batch 3-D self all broadcast the same way addmm's bias
        # does, generalised to a 3-D target (kernel doc, re-checked above).
        for self_flat, self_shape, note in [
            ([1.0, 2.0], (2,), "1-D self -- broadcasts across the last dim (p=2)"),
            ([7.0], (), "0-d self"),
            ([1.0, 1.0, 1.0, 1.0], (2, 2), "2-D self, no batch dim -- broadcasts across the batch"),
            ([1.0, 1.0, 1.0, 1.0], (1, 2, 2), "singleton-batch 3-D self"),
        ]:
            cases.append(
                _baddbmm_case(
                    torch_module, c_module, torch_call, dtype_name,
                    self_flat, self_shape, *_BADDBMM_B1, *_BADDBMM_B2, note=note,
                )
            )

    # The beta=0 quick return, proven rather than asserted, batched --
    # measured: beta=0 with a NaN self gives the clean product (0*nan would
    # be nan if the multiply weren't skipped).
    nan_self = ([float("nan")] * 8, (2, 2, 2))
    cases.append(
        _baddbmm_case(
            torch_module, c_module, torch_call, "float32",
            *nan_self, *_BADDBMM_B1, *_BADDBMM_B2, kwargs=dict(beta=0),
            note="beta=0 with a NaN self -- 0*nan would be nan, torch gives the clean product",
        )
    )

    # alpha=0 is NOT the mirror-image quick return -- addmm's alpha=0 really
    # does skip the multiply entirely on real torch (addmm_cases above proves
    # it with an inf mat1), but baddbmm's does not: `baddbmm(self=zeros,
    # inf_batch1, batch2, alpha=0)` gives `[[nan, nan], [0, 0]], [[0, 0],
    # [0, 0]]]` on real torch -- NaN leaks through the multiply, which is
    # only *scaled* away afterward, not skipped. This used to be a live
    # regression trap (`expect="diverge"`, docs/TAIL.md §2.1) because the
    # kernel's `alpha_zero` branch skipped the matmul unconditionally
    # (copying addmm_scale's rule) and answered a clean `self` instead.
    # Fixed: the kernel now always runs the multiply and only skips the
    # *scale* on alpha==1 (inside `addmm_scale`), so this is a plain `match`
    # again -- promoted per compare.py's own instruction the moment the
    # divergence closed (re-measured: both sides now give the same NaN
    # pattern above).
    inf_b1 = ([float("inf")] + list(range(2, 13)), (2, 2, 3))
    cases.append(
        _baddbmm_case(
            torch_module, c_module, torch_call, "float32",
            *_BADDBMM_SELF, *inf_b1, *_BADDBMM_B2, kwargs=dict(alpha=0),
            note="alpha=0 with an inf in batch1 -- 0*inf is nan, and unlike addmm's bias "
                 "quick return, baddbmm's multiply is NOT skipped on real torch, so the NaN "
                 "leaks through on both sides now (was a KNOWN KERNEL BUG, fixed; see "
                 "docs/TAIL.md §2.1 and docs/KERNELS.md)",
        )
    )

    # int64 alpha truncation, re-measured rather than assumed from the
    # kernel's doc comment: upstream computes alpha=1.9 and alpha=1 as bit-
    # for-bit identical on an int64 triple (the Scalar truncates toward zero
    # before it multiplies), but the shim never gets that far for int64 --
    # candle has no integral matmul kernel at all (the inherited gap
    # _MM_C_ERROR_DTYPES already records for mm/addmm/bmm), so *any* nonzero
    # alpha on int64 raises "candle: unsupported dtype I64 for op matmul"
    # regardless of what alpha's fractional part is. The truncation claim
    # itself is therefore unverifiable as a match case today; this pins the
    # gap instead of the (currently unreachable) behaviour it claimed.
    int_b1 = (list(range(1, 13)), (2, 2, 3))
    int_b2 = ([1, 0, 0, 1, 0, 1, 1, 0, 1, 1, 0, 1], (2, 3, 2))
    int_self = ([0] * 8, (2, 2, 2))
    for alpha, note in [
        (1.9, "alpha=1.9 on int64 -- can't verify truncation, candle has no int64 matmul"),
        (1, "alpha=1 on int64 -- same inherited gap"),
    ]:
        cases.append(
            _baddbmm_case(
                torch_module, c_module, torch_call, "int64",
                *int_self, *int_b1, *int_b2,
                kwargs=dict(alpha=alpha), expect="c_error", note=note,
            )
        )

    # The inherited candle gap: no matmul kernel for the integral dtypes or
    # bfloat16 -- same split mm/addmm/bmm already carry.
    for dtype_name in _MM_C_ERROR_DTYPES:
        cases.append(
            _baddbmm_case(
                torch_module, c_module, torch_call, dtype_name,
                [0, 0, 0, 0], (1, 2, 2), [1, 2, 3, 4], (1, 2, 2), [1, 0, 0, 1], (1, 2, 2),
                expect="c_error",
                note=f"candle's matmul has no kernel for {dtype_name}; torch's CPU baddbmm does. "
                     "Same gap aten.mm.default/aten.addmm.default already carry.",
            )
        )
        cases.append(
            _baddbmm_case(
                torch_module, c_module, torch_call, dtype_name,
                [0, 0, 0, 0], (1, 2, 2), [1, 2, 3, 4], (1, 2, 2), [1, 0, 0, 1], (1, 2, 2),
                kwargs=dict(alpha=0),
                expect="c_error",
                note=f"{dtype_name} with alpha=0 -- used to dodge the gap above (the kernel's old "
                     "alpha_zero quick return skipped the matmul unconditionally, matching torch by "
                     "accident); now that the multiply always runs (docs/TAIL.md §2.1 fix), this hits "
                     "the exact same missing-integral-matmul gap as alpha!=0 above",
            )
        )

    # Refusals. Both sides only need to *refuse*, not agree on wording --
    # measured that upstream's actual check order for a malformed batch1/
    # batch2 rank differs from the shim's ("batch1 must be a 3D tensor" up
    # front), but both raise on every one of these, which is all
    # expect="both_error" requires (see the module docstring above).
    self_t, self_c = pair_from_flat(torch_module, c_module, *_BADDBMM_SELF, "float32")
    f32_b1_t, f32_b1_c = pair_from_flat(torch_module, c_module, *_BADDBMM_B1, "float32")
    b2_full_t, b2_full_c = pair_from_flat(torch_module, c_module, *_BADDBMM_B2, "float32")

    b1_2d_t, b1_2d_c = pair_from_flat(torch_module, c_module, list(range(1, 7)), (2, 3), "float32")
    cases.append(
        Case(
            name="baddbmm(batch1 not 3D rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(self_t, b1_2d_t, b2_full_t),
            run_c=lambda: c_module._aten_dispatch(op, self_c, b1_2d_c, b2_full_c),
            expect="both_error",
            note="batch1 is 2D; baddbmm must not silently fall back to mm's rank",
        )
    )
    b2_2d_t, b2_2d_c = pair_from_flat(torch_module, c_module, [1.0] * 6, (3, 2), "float32")
    cases.append(
        Case(
            name="baddbmm(batch2 not 3D rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(self_t, f32_b1_t, b2_2d_t),
            run_c=lambda: c_module._aten_dispatch(op, self_c, f32_b1_c, b2_2d_c),
            expect="both_error",
            note="batch2 is 2D",
        )
    )
    f64_b2_t, f64_b2_c = pair_from_flat(torch_module, c_module, *_BADDBMM_B2, "float64")
    cases.append(
        Case(
            name="baddbmm(batch1 float32 x batch2 float64 rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(self_t, f32_b1_t, f64_b2_t),
            run_c=lambda: c_module._aten_dispatch(op, self_c, f32_b1_c, f64_b2_c),
            expect="both_error",
            note="torch: 'expected scalar type Float but found Double'",
        )
    )
    f64_self_t, f64_self_c = pair_from_flat(torch_module, c_module, *_BADDBMM_SELF, "float64")
    cases.append(
        Case(
            name="baddbmm(self float64 x batch2 float32 rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(f64_self_t, f32_b1_t, b2_full_t),
            run_c=lambda: c_module._aten_dispatch(op, f64_self_c, f32_b1_c, b2_full_c),
            expect="both_error",
            note="torch: 'Input dtypes must be the same, got: input double, batch1: float, batch2: float'",
        )
    )
    b2_batch1_t, b2_batch1_c = pair_from_flat(
        torch_module, c_module, _BADDBMM_B2[0][:6], (1, 3, 2), "float32"
    )
    cases.append(
        Case(
            name="baddbmm(batch count mismatch rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(self_t, f32_b1_t, b2_batch1_t),
            run_c=lambda: c_module._aten_dispatch(op, self_c, f32_b1_c, b2_batch1_c),
            expect="both_error",
            note="batch1 has batch=2, batch2 has batch=1 -- baddbmm does not broadcast the batch dim",
        )
    )
    bad_inner_t, bad_inner_c = pair_from_flat(torch_module, c_module, [1.0] * 16, (2, 4, 2), "float32")
    cases.append(
        Case(
            name="baddbmm(inner dim mismatch rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(self_t, f32_b1_t, bad_inner_t),
            run_c=lambda: c_module._aten_dispatch(op, self_c, f32_b1_c, bad_inner_c),
            expect="both_error",
            note="batch1 is (2,2,3), batch2 is (2,4,2) -- 3 != 4",
        )
    )
    bad_self_t, bad_self_c = pair_from_flat(torch_module, c_module, [1.0] * 12, (3, 2, 2), "float32")
    cases.append(
        Case(
            name="baddbmm(self not expandable to target rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(bad_self_t, f32_b1_t, b2_full_t),
            run_c=lambda: c_module._aten_dispatch(op, bad_self_c, f32_b1_c, b2_full_c),
            expect="both_error",
            note="self is (3,2,2), target is (2,2,2) -- non-singleton mismatch at dim 0",
        )
    )
    too_many_t, too_many_c = pair_from_flat(torch_module, c_module, [1.0] * 8, (1, 2, 2, 2), "float32")
    cases.append(
        Case(
            name="baddbmm(self has more dims than target rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(too_many_t, f32_b1_t, b2_full_t),
            run_c=lambda: c_module._aten_dispatch(op, too_many_c, f32_b1_c, b2_full_c),
            expect="both_error",
            note="self is 4-D, target is 3-D",
        )
    )
    cases.append(
        Case(
            name="baddbmm(dtype=bool rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [1, 0, 1, 0], (1, 2, 2), "bool")[0],
                _pair(torch_module, c_module, [1, 0, 1, 0], (1, 2, 2), "bool")[0],
                _pair(torch_module, c_module, [1, 0, 1, 0], (1, 2, 2), "bool")[0],
            ),
            run_c=lambda: c_module._aten_dispatch(
                op,
                _pair(torch_module, c_module, [1, 0, 1, 0], (1, 2, 2), "bool")[1],
                _pair(torch_module, c_module, [1, 0, 1, 0], (1, 2, 2), "bool")[1],
                _pair(torch_module, c_module, [1, 0, 1, 0], (1, 2, 2), "bool")[1],
            ),
            expect="both_error",
            note='torch: "baddbmm" not implemented for \'Bool\' -- measured to match the shim\'s '
                 "own wording exactly, unlike the rank refusals above",
        )
    )
    cases.append(
        Case(
            name="baddbmm(dtype=uint32 rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [0, 0, 0, 0], (1, 2, 2), "uint32")[0],
                _pair(torch_module, c_module, [1, 2, 3, 4], (1, 2, 2), "uint32")[0],
                _pair(torch_module, c_module, [1, 0, 0, 1], (1, 2, 2), "uint32")[0],
            ),
            run_c=lambda: c_module._aten_dispatch(
                op,
                _pair(torch_module, c_module, [0, 0, 0, 0], (1, 2, 2), "uint32")[1],
                _pair(torch_module, c_module, [1, 2, 3, 4], (1, 2, 2), "uint32")[1],
                _pair(torch_module, c_module, [1, 0, 0, 1], (1, 2, 2), "uint32")[1],
            ),
            expect="both_error",
            note='torch: "baddbmm" not implemented for \'UInt32\' -- unlike UInt16/UInt64, '
                 "uint32 is at least constructible on the c side, so this exercises baddbmm's "
                 "own refusal rather than a _tensor_from_flat storage gap",
        )
    )

    # Model-scale, batched with the bias -- attention's QK^T scale-and-add,
    # the shape docs/TAIL.md measured bloom reaching for.
    for dtype_name, note in [
        ("float32", "batched depth 512 with a bias -- bloom's scaled QK^T"),
        ("float16", "the same, in the dtype a device would actually run"),
    ]:
        cases.append(
            _big_gemm_case(torch_module, c_module, torch_call, "aten.baddbmm.default",
                           dtype_name, 8, 512, 8, with_bias=True, batch=2, note=note)
        )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # self/batch1/batch2/beta/alpha all by keyword.
    kw_s_t, kw_s_c = pair_from_flat(torch_module, c_module, *_BADDBMM_SELF, "float32")
    kw_b1_t, kw_b1_c = pair_from_flat(torch_module, c_module, *_BADDBMM_B1, "float32")
    kw_b2_t, kw_b2_c = pair_from_flat(torch_module, c_module, *_BADDBMM_B2, "float32")
    cases.append(
        Case(
            name="baddbmm(self=/batch1=/batch2=/beta=/alpha= all by keyword)",
            op="aten.baddbmm.default",
            run_torch=lambda: torch_call(self=kw_s_t, batch1=kw_b1_t, batch2=kw_b2_t, beta=2, alpha=3),
            run_c=lambda: c_module._aten_dispatch(
                "aten.baddbmm.default", self=kw_s_c, batch1=kw_b1_c, batch2=kw_b2_c, beta=2, alpha=3
            ),
        )
    )
    return cases


# --- aten.split_with_sizes.default -------------------------------------
# `split.Tensor` with the chunk sizes spelled out individually -- the
# spelling `gpt_bigcode`'s `c_attn(x).split((embed_dim, kv_dim, kv_dim),
# dim=2)` reaches for. Reuses `_chunk_list_check` (`split_cases`' own
# comparator) since this also answers with a list of tensors.
#
# Unlike `split.Tensor`, sizes must sum *exactly* to the dimension's extent
# -- no "last chunk is short" leniency -- and a size of 0 is fine even when
# the dimension is not itself empty. Both measured against torch 2.13.0
# (see the kernel's own doc comment, re-checked in the refusal cases below).


def _split_with_sizes_case(
    torch_module, c_module, torch_call, dtype_name, flat, shape, sizes, dim=0,
    expect="match", note="",
) -> Case:
    op = "aten.split_with_sizes.default"
    a_t, a_c = pair_from_flat(torch_module, c_module, flat, shape, dtype_name)
    return Case(
        name=f"split_with_sizes(dtype={dtype_name}, shape={shape}, sizes={sizes}, dim={dim}) [{note}]",
        op=op,
        run_torch=lambda: torch_call(a_t, sizes, dim),
        run_c=lambda: c_module._aten_dispatch(op, a_c, sizes, dim),
        expect=expect,
        value_check=_chunk_list_check if expect == "match" else None,
        note=note + " -- returns a list of tensors, see _chunk_list_check",
    )


def split_with_sizes_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.split_with_sizes.default"
    cases: list[Case] = []
    ten = list(range(10))
    for dtype_name in _SPLIT_DTYPES:
        for sizes, note in [
            ([3, 3, 4], "uneven three-way, no leftover"),
            ([10], "one chunk, the whole tensor"),
            ([1] * 10, "ten chunks of one"),
            ([0, 10], "a leading zero-length chunk, dimension not empty"),
            ([10, 0], "a trailing zero-length chunk"),
            ([4, 0, 6], "a zero-length chunk in the middle"),
        ]:
            cases.append(_split_with_sizes_case(torch_module, c_module, torch_call, dtype_name, ten, (10,), sizes, note=note))

    # The GPT-2/gpt_bigcode shape this op exists for: an uneven three-way
    # unpack of a fused QKV projection along the last dim -- query gets the
    # full embedding width, key/value share a narrower one.
    qkv = list(range(24))
    cases.append(
        _split_with_sizes_case(
            torch_module, c_module, torch_call, "float32", qkv, (2, 2, 6), [3, 1, 2], dim=2,
            note="gpt_bigcode's c_attn(x).split((3,1,2), dim=2) -- q wider than k/v",
        )
    )
    cases.append(
        _split_with_sizes_case(
            torch_module, c_module, torch_call, "float32", qkv, (2, 2, 6), [3, 1, 2], dim=-1,
            note="same split, addressed with a negative dim",
        )
    )

    # Refusals. Measured against torch 2.13.0: exact wording is reproduced
    # by the kernel and pinned here (unlike baddbmm's rank checks above,
    # these match verbatim -- see the kernel's own doc comment).
    cases.append(
        Case(
            name="split_with_sizes(sizes sum too small, rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(_pair(torch_module, c_module, ten, (10,), "float32")[0], [3, 3, 3], 0),
            run_c=lambda: c_module._aten_dispatch(
                op, _pair(torch_module, c_module, ten, (10,), "float32")[1], [3, 3, 3], 0
            ),
            expect="both_error",
            note="sizes sum to 9, dimension extent is 10 -- unlike split.Tensor there is no "
                 "leniency here, the caller already spelled out every length",
        )
    )
    cases.append(
        Case(
            name="split_with_sizes(sizes sum too large, rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(_pair(torch_module, c_module, ten, (10,), "float32")[0], [5, 10], 0),
            run_c=lambda: c_module._aten_dispatch(
                op, _pair(torch_module, c_module, ten, (10,), "float32")[1], [5, 10], 0
            ),
            expect="both_error",
            note="sizes sum to 15, dimension extent is 10",
        )
    )
    cases.append(
        Case(
            name="split_with_sizes(negative size entry, rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(_pair(torch_module, c_module, ten, (10,), "float32")[0], [5, -5, 10], 0),
            run_c=lambda: c_module._aten_dispatch(
                op, _pair(torch_module, c_module, ten, (10,), "float32")[1], [5, -5, 10], 0
            ),
            expect="both_error",
            note="a negative entry is refused even though the sum happens to come out to 10",
        )
    )
    cases.append(
        Case(
            name="split_with_sizes(0-d tensor, rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(_pair(torch_module, c_module, [5.0], (), "float32")[0], [], 0),
            run_c=lambda: c_module._aten_dispatch(
                op, _pair(torch_module, c_module, [5.0], (), "float32")[1], [], 0
            ),
            expect="both_error",
            note="torch: 'split expects at least a 1-dimensional tensor' -- the same wording "
                 "split.Tensor gives; upstream does not distinguish the two overloads here",
        )
    )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # self/split_sizes/dim all by keyword.
    kw_t, kw_c = pair_from_flat(torch_module, c_module, ten, (10,), "float32")
    cases.append(
        Case(
            name="split_with_sizes(self=/split_sizes=/dim= all by keyword)",
            op=op,
            run_torch=lambda: torch_call(self=kw_t, split_sizes=[3, 3, 4], dim=0),
            run_c=lambda: c_module._aten_dispatch(op, self=kw_c, split_sizes=[3, 3, 4], dim=0),
            value_check=_chunk_list_check,
        )
    )
    cases.extend(
        c for c in _chunk_member_cases(torch_module, c_module)
        if c.op == "aten.split_with_sizes.default"
    )
    return cases


# --- aten.native_dropout.default -----------------------------------------
#
# The out-of-place dropout (docs/LOSS.md §7). It exists here because `capture`
# refuses mutation, so the eager composite's `bernoulli_` made a `.train()`
# forward unrecordable -- not because anything needed a faster dropout.
#
# **It is not the composite with the mutation removed**, and the case list is
# built around the three places it differs. Two are invisible in `float32`:
#
#   * the mask is `bool`, not the input's dtype;
#   * the scale goes on the OUTPUT (`input.mul(mask).mul_(scale)`), not on the
#     mask (`noise.div_(1-p)`), and it is **narrowed to the input's dtype
#     first** -- which a standalone `Tensor.mul_(python_float)` does not do;
#   * `p` outside [0,1] raises `bernoulli_`'s message naming `1 - p`, where
#     `torch.dropout` raises its own naming `p`.
#
# The second was found by measurement and not by reading the source. Stepping
# `output.mul_(scale)` from Python gives a different answer than the kernel
# does, and only in the reduced dtypes:
#
#     bfloat16, x = -9.875, p = 0.7, a survivor
#       x.mul(mask).mul_(scale)     -> -33.0
#       native_dropout(...)         -> -32.75      = -9.875 * bfloat16(scale)
#
# `_ND_SURVIVOR` below is that value, carried as a case so the rule is pinned
# rather than remembered. The un-narrowed reading misses 41 of 377 in the
# development harness and **0 of 377 in float32 alone**.

_ND_DTYPES = ["float64", "float32", "float16", "bfloat16"]
# -9.875 is exactly representable in every dtype here, and 0.7 makes
# `1/(1-p)` = 3.3333... a value whose bfloat16 and float32 roundings differ in
# the first place that matters. Measured, not chosen for looks.
_ND_SURVIVOR = -9.875


def _nd_pair_check(t_res, c_res) -> tuple[bool, str]:
    """`(output, mask)`, both exact.

    Exact rather than tolerant for the same reason `_bit_exact` is: the subject
    is *where the rounding happens*, so a tolerance is the one thing that
    cannot be allowed to absorb it. Measured, this kernel agrees with upstream
    bit for bit on all 377 combinations in the development harness, so
    exactness is a bound it meets.
    """
    try:
        parts = list(zip(("output", "mask"), (t_res[0], t_res[1]), (c_res[0], c_res[1])))
    except (TypeError, IndexError, KeyError) as e:
        return False, f"expected a 2-element (output, mask) result on both sides: {e!r}"
    for label, t_part, c_part in parts:
        t_dtype, c_dtype = dt.dtype_name(t_part.dtype), dt.dtype_name(c_part.dtype)
        if t_dtype != c_dtype:
            return False, (
                f"{label} dtype mismatch: torch={t_dtype} c={c_dtype}"
                + ("  -- the mask is bool on the normal path and the INPUT's dtype "
                   "on the numel==0 path; upstream takes that return before the "
                   "branch that would have made it bool" if label == "mask" else "")
            )
        t_shape = tuple(int(x) for x in t_part.shape)
        c_shape = tuple(int(x) for x in c_part.shape)
        if t_shape != c_shape:
            return False, f"{label} shape mismatch: torch={t_shape} c={c_shape}"
        t_flat = _flatten_values(t_part.tolist())
        c_flat = _flatten_values(c_part.tolist())
        if len(t_flat) != len(c_flat):
            return False, f"{label} length differs: torch={len(t_flat)} c={len(c_flat)}"
        for i, (x, y) in enumerate(zip(t_flat, c_flat)):
            if isinstance(x, bool) or isinstance(y, bool):
                if x != y:
                    return False, f"{label}[{i}] mismatch: torch={x!r} c={y!r}"
                continue
            xf, yf = float(x), float(y)
            if math.isnan(xf) or math.isnan(yf):
                if math.isnan(xf) and math.isnan(yf):
                    continue
                return False, f"{label}[{i}] mismatch: torch={x!r} c={y!r} (NaN on one side only)"
            if xf != yf:
                return False, (
                    f"{label}[{i}] mismatch: torch={x!r} c={y!r} -- exact agreement "
                    f"is required here; the scale's rounding is the subject "
                    f"(docs/LOSS.md §7)"
                )
    return True, "output and mask both matched exactly"


def native_dropout_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.native_dropout.default"
    cases: list[Case] = []
    SEED = 1234

    def seeded(flat, shape, dtype_name, p, train):
        def run_torch():
            torch_module.manual_seed(SEED)
            t = _pair(torch_module, c_module, flat, shape, dtype_name)[0]
            return torch_call(t, p, train)

        def run_c():
            c_module._shim_manual_seed(SEED)
            c = _pair(torch_module, c_module, flat, shape, dtype_name)[1]
            return c_module._aten_dispatch(op, c, p, train)

        return run_torch, run_c

    vals24 = [round((((i * 7919 + 13) % 2000) / 100.0 - 10.0), 6) for i in range(24)]
    for dtype_name in _ND_DTYPES:
        for shape in [(4, 6), (24,), (2, 3, 4)]:
            for p in [0.0, 0.25, 0.5, 0.7, 1.0]:
                for train in [True, False, None]:
                    run_torch, run_c = seeded(vals24, shape, dtype_name, p, train)
                    cases.append(
                        Case(
                            name=(f"native_dropout(dtype={dtype_name}, shape={shape}, "
                                  f"p={p}, train={train})"),
                            op=op,
                            run_torch=run_torch,
                            run_c=run_c,
                            value_check=_nd_pair_check,
                            note=("train=None means True upstream -- "
                                  "`!train.has_value() || *train`"
                                  if train is None else ""),
                        )
                    )

    # The survivor whose scale rounding separates the two readings. One element,
    # forced to survive by p=0.0... which also makes scale 1. So instead: a
    # 24-element run at p=0.7 where at least one survivor is -9.875, and the
    # *whole* tensor is that value, so every survivor is the separating one.
    for dtype_name in _ND_DTYPES:
        for p in [0.7, 0.3, 0.9]:
            run_torch, run_c = seeded([_ND_SURVIVOR] * 24, (24,), dtype_name, p, True)
            cases.append(
                Case(
                    name=(f"native_dropout(dtype={dtype_name}, p={p}, every element "
                          f"{_ND_SURVIVOR}) [the scale-rounding separator]"),
                    op=op,
                    run_torch=run_torch,
                    run_c=run_c,
                    value_check=_nd_pair_check,
                    note="the scale is narrowed to the input's dtype before it "
                         "multiplies; a standalone Tensor.mul_(float) does not narrow, "
                         "and in bfloat16 the two answers are -32.75 and -33.0",
                )
            )

    # The stream afterwards, which is where a short-circuit hides. `p=0` and
    # `p=1` still draw `numel` times upstream, exactly as `bernoulli_` does --
    # and the returned tensor is right either way, so only the *following* draw
    # can tell.
    for p in [0.0, 1.0, 0.5]:
        for train in [True, False]:
            def before_torch(p=p, train=train):
                torch_module.ops.aten.native_dropout.default(
                    torch_module.zeros(9), p, train)

            def before_c(p=p, train=train):
                c_module._aten_dispatch(
                    op, c_module._tensor_from_flat([0.0] * 9, [9],
                                                   dtype=c_module.float32), p, train)

            run_torch, run_c = _seeded_stream_after(
                torch_module, c_module, before_torch, before_c)
            cases.append(
                Case(
                    name=f"native_dropout(p={p}, train={train}) then uniform_ "
                         f"[the draws AFTER it]",
                    op=op,
                    run_torch=run_torch,
                    run_c=run_c,
                    value_check=_rng_stream_check(bitwise=True, bounds=(0.0, 1.0)),
                    note="train=False draws NOTHING (it takes the ones_like/clone "
                         "branch) and train=True draws numel times even at p=0 and "
                         "p=1. Every case that looks at the returned tensor passes "
                         "both a short-circuit and a spurious draw",
                )
            )

    edges = [
        ([1.0, -1.0, 0.0, -0.0, float("inf"), float("-inf")], (6,), 1.0, True,
         "p=1: the scale is guarded to 0, so masked-out elements keep their sign "
         "and +-inf becomes NaN -- a zeros_like would give a plain 0.0"),
        ([1.0, -1.0, 0.0, -0.0, float("inf"), float("-inf")], (6,), 0.0, True,
         "p=0: every element survives and the scale is exactly 1"),
        ([1.0, float("nan"), 2.0], (3,), 0.5, True, "NaN passes through a survivor"),
        ([], (0,), 0.5, True,
         "numel 0: upstream returns the INPUT ITSELF and a mask of the input's "
         "dtype -- not bool, because that return is taken above the branch that "
         "would have made it bool"),
        ([], (0, 3), 0.5, False, "the same early return, train=False"),
    ]
    for flat, shape, p, train, note in edges:
        run_torch, run_c = seeded(flat, shape, "float32", p, train)
        cases.append(
            Case(
                name=f"native_dropout(float32, shape={shape}, p={p}, train={train}) "
                     f"[{note[:40]}]",
                op=op,
                run_torch=run_torch,
                run_c=run_c,
                value_check=_nd_pair_check,
                note=note,
            )
        )

    # Refusals. `p` outside [0,1] raises **bernoulli_'s** message, and it names
    # `1 - p`: native_dropout has no range check of its own, unlike
    # torch.dropout, which has one and names `p`.
    for p in [1.5, -0.5, float("nan")]:
        t_t, t_c = _pair(torch_module, c_module, [1.0, 2.0, 3.0], (3,), "float32")
        cases.append(
            Case(
                name=f"native_dropout(p={p!r}) [refused on both sides]",
                op=op,
                run_torch=lambda t_t=t_t, p=p: torch_call(t_t, p, True),
                run_c=lambda t_c=t_c, p=p: c_module._aten_dispatch(op, t_c, p, True),
                expect="both_error",
                note="torch: 'bernoulli_ expects p to be in [0, 1], but got p=<1-p>'. "
                     "The message names the SURVIVAL probability, because the only "
                     "check on the road is bernoulli_'s",
            )
        )
    # ...and train=False takes the branch with no bernoulli_ in it, so the same
    # out-of-range p is ACCEPTED. Measured; it is the sharpest evidence that the
    # check belongs to bernoulli_ and not to native_dropout.
    for p in [1.5, -0.5]:
        run_torch, run_c = seeded([1.0, 2.0, 3.0], (3,), "float32", p, False)
        cases.append(
            Case(
                name=f"native_dropout(p={p!r}, train=False) [ACCEPTED on both sides]",
                op=op,
                run_torch=run_torch,
                run_c=run_c,
                value_check=_nd_pair_check,
                note="train=False never reaches bernoulli_, so there is nothing to "
                     "refuse an out-of-range p -- a range check written into "
                     "native_dropout itself would reject a call upstream accepts",
            )
        )
    for dtype_name, why in [
        ("int64", "RuntimeError: result type Float can't be cast to the desired "
                  "output type Long -- it is `mul_(scale)` that raises, not a "
                  "dtype guard at the top"),
        ("bool", "the same, for Bool"),
    ]:
        t_t, t_c = _pair(torch_module, c_module, [1, 0, 1], (3,), dtype_name)
        cases.append(
            Case(
                name=f"native_dropout(dtype={dtype_name}) [refused on both sides]",
                op=op,
                run_torch=lambda t_t=t_t: torch_call(t_t, 0.5, True),
                run_c=lambda t_c=t_c: c_module._aten_dispatch(op, t_c, 0.5, True),
                expect="both_error",
                note=why,
            )
        )

    # --- object identity, which a value comparison cannot see --------------
    #
    # `native_dropout` returns the input **itself** when `numel == 0` and a
    # **copy** otherwise -- including on the `train=False` branch, where
    # `torch.dropout` returns the input itself. Two dropout spellings, opposite
    # answers to `out is x`, and neither shows up in any element.
    #
    # Expressed as a 1-element tensor holding the boolean, because that is the
    # only shape this harness compares.
    for shape, p, train, expect in [
        ((3,), 0.5, False, "a copy -- output = input.clone()"),
        ((3,), 0.0, True, "a copy: p==0 has no short-circuit here, unlike torch.dropout"),
        ((0, 3), 0.5, True, "the SAME object -- the numel==0 early return"),
        ((0, 3), 0.5, False, "the same object, on the train=False path too"),
    ]:
        n = 1
        for s in shape:
            n *= s

        def rt(shape=shape, n=n, p=p, train=train):
            t = _pair(torch_module, c_module, [1.0] * n, shape, "float32")[0]
            return torch_module.tensor([float(torch_call(t, p, train)[0] is t)])

        def rc(shape=shape, n=n, p=p, train=train):
            c = _pair(torch_module, c_module, [1.0] * n, shape, "float32")[1]
            same = c_module._aten_dispatch(op, c, p, train)[0] is c
            return c_module._tensor_from_flat([float(same)], [1],
                                              dtype=c_module.float32)

        cases.append(
            Case(
                name=f"native_dropout(shape={shape}, p={p}, train={train}) "
                     f"[is the output the input object? -- {expect}]",
                op=op,
                run_torch=rt,
                run_c=rc,
                note="identity, not values: `output = input.clone()` on the train "
                     "branch and `return input` on the numel==0 one. No element "
                     "differs either way",
            )
        )

    # The spellings.
    for label, fn_t, fn_c in [
        ("torch.native_dropout(x, p, train)",
         lambda t: torch_module.native_dropout(t, 0.5, True),
         lambda c: c_module._VariableFunctions.native_dropout(c, 0.5, True)),
    ]:
        def rt(fn_t=fn_t):
            torch_module.manual_seed(SEED)
            return fn_t(_pair(torch_module, c_module, vals24, (24,), "float32")[0])

        def rc(fn_c=fn_c):
            c_module._shim_manual_seed(SEED)
            return fn_c(_pair(torch_module, c_module, vals24, (24,), "float32")[1])

        cases.append(
            Case(
                name=f"native_dropout via {label}",
                op=op,
                run_torch=rt,
                run_c=rc,
                value_check=_nd_pair_check,
                note="hasattr(torch, 'native_dropout') is True on 2.13.0, so the free "
                     "name exists upstream and golden -- which compares by dispatch "
                     "key -- would not have noticed it missing",
            )
        )
    return cases


# --- aten._log_softmax.default -------------------------------------------
#
# The first half of a cross-entropy forward (docs/LOSS.md). It looks like
# `softmax_cases` above and one thing in it is not like `_softmax` at all:
#
#   **upstream has TWO log-softmax kernels and they do different arithmetic.**
#   `serial_vec_log_softmax_lastdim_range` (chosen when `dim` is the trailing
#   axis) round-trips the sum of exponentials, and then its logarithm, through
#   a `scalar_t` buffer; `serial_vec_logsoftmax_range` (every other `dim`)
#   holds both in `float`. On `bfloat16` that is two roundings to 8 significand
#   bits that the strided path does not do.
#
# For `float32` and `float64` the narrowing is the identity, so **a
# float-only case list cannot see the split at all** -- which is why the
# dtype x dim grid below runs all four dtypes against both paths rather than
# spot-checking one.
#
# It still would not be enough. One `bfloat16` ULP is ~0.4% relative and
# `dtypes.py` allows 6%, so an ordinary input that differs by a ULP passes
# whichever way the kernel is written. `_LOG_SOFTMAX_SEPARATOR` below is the
# input that does not: `[0, ln(0.002)]` sums to 1.00203, which is inside half a
# `bfloat16` ULP of exactly 1.0, so the last-dim path takes `log(1) = 0` and
# the strided path takes `log(1.00203) = 0.00198`. The first output element is
# `0.0` one way and `-0.00198` the other, a *relative* difference of 1.0.
# Measured, not chosen: the same input in `float16` differs by 4.6e-05, which
# `float16`'s 5e-3 atol absorbs, so `float16` is carried as documentation of
# the near miss rather than as a separator.

_LOG_SOFTMAX_DTYPES = ["float64", "float32", "float16", "bfloat16"]

# ln(0.002), to float32 precision. Written out rather than computed so the
# two sides cannot disagree about `math.log`.
_LOG_SOFTMAX_SEPARATOR = -6.214608098422191


def _bit_exact(t_res, c_res) -> tuple[bool, str]:
    """Equality with no tolerance at all, for the cases whose whole subject is
    a rounding rule.

    **The default pipeline cannot do this job, and that was measured rather
    than assumed.** `dtypes.py` gives `bfloat16` `atol=6e-2`, and the
    narrowing this separates moves a value by at most one ULP or 0.002,
    whichever is larger -- so `math.isclose` absorbs it for *every* input, not
    just the easy ones. The bound is structural: the sum's `bfloat16` rounding
    is at most 2^-9 relative, so `log(sum)` moves by at most 0.00195 absolute
    no matter how the input is chosen, and reaching an absolute 6e-2 would
    need `log(sum) > 16`, i.e. a reduction over e^16 elements.

    **Dtype and shape are checked here, not by the caller.** `compare.py`
    hands a `value_check` the whole job and skips its own pipeline entirely, so
    the first draft of this function -- values only -- was reported by
    `--self-test` as accepting a wrong answer under both the `shape` and the
    `dtype` fault modes. That is the self-test doing exactly what it is for.
    """
    t_dtype, c_dtype = dt.dtype_name(t_res.dtype), dt.dtype_name(c_res.dtype)
    if t_dtype != c_dtype:
        return False, f"dtype mismatch: torch={t_dtype} c={c_dtype}"
    t_shape = tuple(int(x) for x in t_res.shape)
    c_shape = tuple(int(x) for x in c_res.shape)
    if t_shape != c_shape:
        return False, f"shape mismatch: torch={t_shape} c={c_shape}"
    t_flat, c_flat = _flatten_values(t_res.tolist()), _flatten_values(c_res.tolist())
    if len(t_flat) != len(c_flat):
        return False, f"length differs: torch={len(t_flat)} c={len(c_flat)}"
    for i, (x, y) in enumerate(zip(t_flat, c_flat)):
        xf, yf = float(x), float(y)
        if math.isnan(xf) or math.isnan(yf):
            if math.isnan(xf) and math.isnan(yf):
                continue
            return False, f"index {i}: torch={x!r} c={y!r} (NaN mismatch)"
        if xf != yf:
            return False, (
                f"index {i}: torch={x!r} c={y!r} -- these must agree BIT FOR BIT; "
                f"a tolerance here would absorb the whole effect (see _bit_exact)"
            )
    return True, ""


def log_softmax_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten._log_softmax.default"
    cases: list[Case] = []

    # Values spread wide enough that the row max is not the first element and
    # the exponentials do not all collapse to one term.
    six = [1.0, 2.0, 3.0, 0.0, -1.5, 0.5]
    scenarios = [
        (six, (2, 3), -1, "last dim -- the narrowing path"),
        (six, (2, 3), 0, "first dim -- the float path"),
        (six, (6,), 0, "1-D: dim 0 is the trailing axis, so the narrowing path"),
        (six, (3, 2, 1), 1, "inner extent 1 but dim is NOT the trailing axis -- "
                            "still the strided kernel, which `inner == 1` would get wrong"),
        ([3.0], (), -1, "0-d: upstream views it as (1,), so the answer is log(1) = 0"),
    ]
    for dtype_name in _LOG_SOFTMAX_DTYPES:
        for flat, shape, dim, note in scenarios:
            cases.append(
                Case(
                    name=f"_log_softmax(dtype={dtype_name}, shape={shape}, dim={dim}) [{note}]",
                    op=op,
                    run_torch=lambda flat=flat, shape=shape, dim=dim, dtype_name=dtype_name: torch_call(
                        _pair(torch_module, c_module, flat, shape, dtype_name)[0], dim, False
                    ),
                    run_c=lambda flat=flat, shape=shape, dim=dim, dtype_name=dtype_name: c_module._aten_dispatch(
                        op, _pair(torch_module, c_module, flat, shape, dtype_name)[1], dim, False
                    ),
                    # The reduced dtypes agree with upstream bit for bit here
                    # (measured, every shape/dim in this list), so they are held
                    # to that. float32/float64 are not: this kernel sums
                    # serially where upstream reduces over vector lanes, which
                    # costs up to 9.5e-07 in float32 -- inside the tolerance,
                    # and the reason no float32 case in this file can separate
                    # a summation order.
                    value_check=_bit_exact if dtype_name in ("float16", "bfloat16") else None,
                    note=note,
                )
            )

    # The separator, both ways round. `(1, 2)` at `dim=-1` takes the last-dim
    # kernel; the same two numbers as `(2, 1)` at `dim=0` take the strided one.
    # A shim that used one rule for both fails exactly one of each pair, in
    # bfloat16, by 100% relative -- past any tolerance in dtypes.py.
    for dtype_name in _LOG_SOFTMAX_DTYPES:
        for shape, dim, which in [((1, 2), -1, "last-dim kernel: sum narrows, log(1.0) = 0"),
                                  ((2, 1), 0, "strided kernel: sum stays float, log(1.00203)")]:
            cases.append(
                Case(
                    name=f"_log_softmax(dtype={dtype_name}, shape={shape}, dim={dim}) "
                         f"[the narrowing separator -- {which}]",
                    op=op,
                    run_torch=lambda shape=shape, dim=dim, dtype_name=dtype_name: torch_call(
                        _pair(torch_module, c_module, [0.0, _LOG_SOFTMAX_SEPARATOR],
                              shape, dtype_name)[0], dim, False
                    ),
                    run_c=lambda shape=shape, dim=dim, dtype_name=dtype_name: c_module._aten_dispatch(
                        op, _pair(torch_module, c_module, [0.0, _LOG_SOFTMAX_SEPARATOR],
                                  shape, dtype_name)[1], dim, False
                    ),
                    # **This must be exact, and that is the whole point.**
                    # The first draft of these two cases used the default
                    # tolerance and could not fail: applied to a shim that
                    # never narrows, and to one that always narrows, golden
                    # reported 0 failures both times. bfloat16's atol is 6e-2
                    # and the effect is 0.002. See `_bit_exact`.
                    value_check=_bit_exact,
                    note="the only case in this list that can tell the two upstream "
                         "log-softmax kernels apart",
                )
            )

    edge = [
        ([1.0, float("-inf"), 2.0], (3,), "one masked position",
         "-inf survives as -inf: exp(-inf - max) is a clean 0, and the output is "
         "-inf - log(sum), not a NaN"),
        ([float("-inf"), float("-inf")], (2,), "a fully masked row",
         "NaN on both sides -- `_log_softmax` has no `_safe_softmax` twin, so this "
         "agreement is the whole contract"),
        ([float("inf"), 1.0], (2,), "+inf",
         "inf - inf is NaN and it poisons the row, on both sides"),
        ([float("nan"), 1.0], (2,), "NaN input", "NaN out, both elements"),
        ([1000.0, 1001.0, 999.0], (3,), "large logits",
         "the max subtraction is the only thing between this and inf/inf"),
        ([], (0,), "empty", "no lane to reduce"),
        ([1.0, 2.0], (2, 0), "zero extent along dim -- wait, no elements at all",
         "numel 0: upstream returns before the kernel runs"),
    ]
    for flat, shape, label, note in edge:
        n = 1
        for s in shape:
            n *= s
        cases.append(
            Case(
                name=f"_log_softmax(float32, {label})",
                op=op,
                run_torch=lambda flat=flat[:n], shape=shape: torch_call(
                    _pair(torch_module, c_module, flat, shape, "float32")[0], -1, False
                ),
                run_c=lambda flat=flat[:n], shape=shape: c_module._aten_dispatch(
                    op, _pair(torch_module, c_module, flat, shape, "float32")[1], -1, False
                ),
                note=note,
            )
        )

    # Both refusals, and -- unlike `_softmax` -- the integral one names a
    # *different kernel* depending on which side of the last-dim fork the call
    # falls. Two cases, not one, because a shim with a single hard-coded
    # message passes the first and fails the second.
    for shape, dim, kernel in [((4,), 0, "log_softmax_lastdim_kernel_impl"),
                               ((2, 3), 1, "log_softmax_lastdim_kernel_impl"),
                               ((2, 3), 0, "log_softmax_kernel_impl")]:
        n = shape[0] * (shape[1] if len(shape) > 1 else 1)
        cases.append(
            Case(
                name=f"_log_softmax(int64 shape={shape} dim={dim} rejected on both sides)",
                op=op,
                run_torch=lambda shape=shape, dim=dim, n=n: torch_call(
                    _pair(torch_module, c_module, list(range(n)), shape, "int64")[0], dim, False
                ),
                run_c=lambda shape=shape, dim=dim, n=n: c_module._aten_dispatch(
                    op, _pair(torch_module, c_module, list(range(n)), shape, "int64")[1], dim, False
                ),
                expect="both_error",
                note=f'torch: NotImplementedError, "{kernel}" not implemented for \'Long\'',
            )
        )

    for dtype_name, why in [
        ("float32", "torch: 'softmax with half to float conversion is not supported on CPU'"),
        ("float16", "the same refusal, for the dtype whose name the flag comes from"),
    ]:
        cases.append(
            Case(
                name=f"_log_softmax(dtype={dtype_name}, half_to_float=True rejected on both sides)",
                op=op,
                run_torch=lambda dtype_name=dtype_name: torch_call(
                    _pair(torch_module, c_module, [1.0, 2.0, 3.0], (3,), dtype_name)[0], -1, True
                ),
                run_c=lambda dtype_name=dtype_name: c_module._aten_dispatch(
                    op, _pair(torch_module, c_module, [1.0, 2.0, 3.0], (3,), dtype_name)[1], -1, True
                ),
                expect="both_error",
                note=why,
            )
        )
    cases.append(
        Case(
            name="_log_softmax(dim out of range rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [1.0, 2.0, 3.0], (3,), "float32")[0], 5, False
            ),
            run_c=lambda: c_module._aten_dispatch(
                op, _pair(torch_module, c_module, [1.0, 2.0, 3.0], (3,), "float32")[1], 5, False
            ),
            expect="both_error",
            note="IndexError on both sides",
        )
    )

    kw_t, kw_c = _pair(torch_module, c_module, six, (2, 3), "float32")
    cases.append(
        Case(
            name="_log_softmax(self=/dim=/half_to_float= all by keyword)",
            op=op,
            run_torch=lambda: torch_call(self=kw_t, dim=-1, half_to_float=False),
            run_c=lambda: c_module._aten_dispatch(op, self=kw_c, dim=-1, half_to_float=False),
        )
    )

    # --- the spellings ---------------------------------------------------
    #
    # Everything above compares by dispatch key, and a dispatch key is exactly
    # what a *caller* does not have. `F.log_softmax(x, dim)` is
    # `input.log_softmax(dim)` in the vendored `torch/nn/functional.py`, so with
    # the kernel present and the member absent it still refuses -- which is how
    # this landed the first time. These cases go through the names instead.
    def _spellings():
        t, c = _pair(torch_module, c_module, six, (2, 3), "float32")
        return t, c

    spellings = [
        ("torch.log_softmax(x, dim)",
         lambda t: torch_module.log_softmax(t, -1),
         lambda c: c_module._VariableFunctions.log_softmax(c, -1),
         "the free public spelling -- a Python-level composite, NOT an "
         "overloads.json entry, because aten::log_softmax.int is "
         "CompositeImplicitAutograd"),
        ("Tensor.log_softmax(dim)",
         lambda t: t.log_softmax(-1),
         lambda c: c.log_softmax(-1),
         "the member F.log_softmax actually calls"),
        ("torch._log_softmax(x, dim, False)",
         lambda t: torch_module._log_softmax(t, -1, False),
         lambda c: c_module._VariableFunctions._log_softmax(c, -1, False),
         "the private free spelling -- this one IS an overloads.json entry, "
         "because aten::_log_softmax is the dispatched leaf"),
        ("torch.log_softmax(x, dim, dtype=float64)",
         lambda t: torch_module.log_softmax(t, -1, dt.torch_dtype(torch_module, "float64")),
         lambda c: c_module._VariableFunctions.log_softmax(c, -1, dt.c_dtype(c_module, "float64")),
         "dtype= casts first, then calls the kernel -- so the result is float64"),
        ("Tensor.log_softmax(dim, dtype=x.dtype)",
         lambda t: t.log_softmax(-1, dt.torch_dtype(torch_module, "float32")),
         lambda c: c.log_softmax(-1, dt.c_dtype(c_module, "float32")),
         "a no-op dtype emits no conversion call on either side"),
    ]
    for label, fn_t, fn_c, note in spellings:
        cases.append(
            Case(
                name=f"_log_softmax via {label}",
                op=op,
                run_torch=lambda fn_t=fn_t: fn_t(_spellings()[0]),
                run_c=lambda fn_c=fn_c: fn_c(_spellings()[1]),
                note=note,
            )
        )

    return cases


# --- aten.nll_loss_forward.default ---------------------------------------
#
# The second half of a cross-entropy forward (docs/LOSS.md §3). Two things
# about it need saying before the case list.
#
# **It returns TWO tensors and every caller throws the second away.**
# `total_weight` is what `nll_loss_backward` divides by, so it is not
# decoration -- and a forward-only test cannot see it, which is the exact shape
# of bug this repository keeps finding. `_nll_pair_check` below therefore
# checks both members with equal weight, and the grid deliberately includes the
# combination where `total_weight` is *not* what the loss suggests:
#
#     reduction=none, 2-D input   ->  total_weight = 0, always, even weighted
#
# because upstream writes `*total_weight_data = 0` at the top of
# `nll_loss_out_frame` and then returns before it is ever updated.
#
# **The sum is a cascade, so the batch size is part of the input.** Upstream
# accumulates into 8 partial sums with a carry every 16 elements, all in
# `scalar_t`, and an ignored target `continue`s past the carry -- so
# `ignore_index` changes *where* the carries land. A plain left-to-right sum
# disagrees from n=8 in `bfloat16` and from n=300 in `float32`. The grid runs
# 10 batch sizes chosen around the carry boundaries (16, 17, 64, 65) for that
# reason, not for coverage's sake.

_NLL_DTYPES = ["float64", "float32", "float16", "bfloat16"]
_NLL_CLASSES = 7
# Reduction constants, as `torch.nn._reduction` spells them.
_NLL_NONE, _NLL_MEAN, _NLL_SUM = 0, 1, 2


def _nll_pair_check(t_res, c_res) -> tuple[bool, str]:
    """`(output, total_weight)`, both checked.

    `total_weight` is the member a forward-only comparison cannot see, so it
    gets the same dtype/shape/value treatment as the loss rather than being
    glanced at. NaN is a *result* here and not a failure: mean over an entirely
    ignored batch is `0/0`, deliberately (upstream's own choice,
    pytorch#64572), and the two sides agreeing on it is what is checked.
    """
    try:
        parts = list(zip(("output", "total_weight"), (t_res[0], t_res[1]), (c_res[0], c_res[1])))
    except (TypeError, IndexError, KeyError) as e:
        return False, f"expected a 2-element (output, total_weight) result on both sides: {e!r}"
    for label, t_part, c_part in parts:
        t_dtype, c_dtype = dt.dtype_name(t_part.dtype), dt.dtype_name(c_part.dtype)
        if t_dtype != c_dtype:
            return False, f"{label} dtype mismatch: torch={t_dtype} c={c_dtype}"
        t_shape = tuple(int(x) for x in t_part.shape)
        c_shape = tuple(int(x) for x in c_part.shape)
        if t_shape != c_shape:
            return False, f"{label} shape mismatch: torch={t_shape} c={c_shape}"
        t_flat = _flatten_values(t_part.tolist())
        c_flat = _flatten_values(c_part.tolist())
        if len(t_flat) != len(c_flat):
            return False, f"{label} length differs: torch={len(t_flat)} c={len(c_flat)}"
        for i, (x, y) in enumerate(zip(t_flat, c_flat)):
            xf, yf = float(x), float(y)
            if math.isnan(xf) or math.isnan(yf):
                if math.isnan(xf) and math.isnan(yf):
                    continue
                return False, f"{label}[{i}] mismatch: torch={x!r} c={y!r} (NaN on one side only)"
            # **Exact, not close.** The cascade is the subject: a naive sum
            # differs from upstream by well under `float32`'s 1e-5 for a small
            # batch, so a tolerance here would let the wrong summation through
            # for every batch size below a few hundred. Measured: this kernel
            # agrees with upstream bit for bit on 1200 of 1200 combinations
            # (25 batch sizes x 4 dtypes x 2 reductions x 3 ignore_index x
            # weighted/not), so exactness is a bound it actually meets.
            if xf != yf:
                return False, (
                    f"{label}[{i}] mismatch: torch={x!r} c={y!r} -- these must agree BIT "
                    f"FOR BIT; the cascade summation is what this case is about and a "
                    f"tolerance would absorb it (docs/LOSS.md §3.2)"
                )
    return True, "output and total_weight both matched exactly"


def nll_loss_forward_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.nll_loss_forward.default"
    cases: list[Case] = []
    C = _NLL_CLASSES

    def logits(n, dtype_name):
        # Deterministic, spread over a range wide enough that the cascade's
        # carry order is visible, and not a progression that sums the same in
        # any order.
        flat = [(((i * 7919 + 13) % 2000) / 100.0 - 10.0) for i in range(n * C)]
        return _pair(torch_module, c_module, flat, (n, C), dtype_name)

    def targets(n, mod=C):
        flat = [(i * 13 + 5) % mod for i in range(n)]
        return _pair(torch_module, c_module, flat, (n,), "int64")

    def weights(dtype_name):
        return _pair(torch_module, c_module,
                     [round(0.1 + 0.37 * i, 6) for i in range(C)], (C,), dtype_name)

    # Batch sizes around the cascade's carry boundaries: level_step is 16, so
    # 16/17 and 64/65 are where a wrong carry rule first shows.
    for dtype_name in _NLL_DTYPES:
        for n in [1, 2, 3, 8, 16, 17, 64, 65, 300]:
            for reduction, rn in [(_NLL_NONE, "none"), (_NLL_MEAN, "mean"), (_NLL_SUM, "sum")]:
                for use_w in (False, True):
                    for ignore in (-100, 3):
                        note = (
                            "total_weight is 0 here whatever the loss says"
                            if reduction == _NLL_NONE
                            else "an ignored target skips the cascade carry, not just the add"
                            if ignore == 3 else ""
                        )
                        cases.append(
                            Case(
                                name=(f"nll_loss_forward(dtype={dtype_name}, n={n}, "
                                      f"reduction={rn}, weight={use_w}, ignore_index={ignore})"),
                                op=op,
                                run_torch=lambda n=n, dtype_name=dtype_name, use_w=use_w,
                                                 reduction=reduction, ignore=ignore: torch_call(
                                    logits(n, dtype_name)[0], targets(n)[0],
                                    weights(dtype_name)[0] if use_w else None,
                                    reduction, ignore,
                                ),
                                run_c=lambda n=n, dtype_name=dtype_name, use_w=use_w,
                                             reduction=reduction, ignore=ignore: c_module._aten_dispatch(
                                    op, logits(n, dtype_name)[1], targets(n)[1],
                                    weights(dtype_name)[1] if use_w else None,
                                    reduction, ignore,
                                ),
                                value_check=_nll_pair_check,
                                note=note,
                            )
                        )

    # --- total_weight is a CAST OF A COUNT, not a sum ----------------------
    #
    # Upstream's unweighted branch is `static_cast<scalar_t>(batch_size -
    # num_ignored)`: the count is formed in `int64` and rounded **once**.
    # Accumulating `1.0` through the same cascade the loss uses is the obvious
    # alternative and it agrees for every batch size in the grid above -- which
    # is how it got through the first sabotage pass with 0 failures.
    #
    # It stops agreeing where a `bfloat16` partial sum saturates: at 256 the
    # ULP is 2, so `256 + 1` is `256` and the cascade stops counting, while the
    # single cast still rounds 258 to 258 exactly. Measured, not guessed --
    # searched over n in [250,270] u [500,530] u {1000,1023,1024,1025,2049,
    # 4097,300,301,320,384,385}, and 300 (the largest batch in the grid above)
    # is NOT one of the ten that separate:
    #
    #     n=258 bfloat16   cast 258   cascade-of-ones 256
    #     n=515 bfloat16   cast 516   cascade-of-ones 512
    #
    # `float16` never separates in that range: its 11-bit significand counts
    # exactly past 2048, well beyond any batch worth putting in a case list.
    for n, reduction, rn in [(258, _NLL_MEAN, "mean"), (258, _NLL_SUM, "sum")]:
        cases.append(
            Case(
                name=(f"nll_loss_forward(bfloat16, n={n}, reduction={rn}) "
                      f"[total_weight is one cast of a count, not a cascade of ones]"),
                op=op,
                run_torch=lambda n=n, reduction=reduction: torch_call(
                    logits(n, "bfloat16")[0], targets(n)[0], None, reduction, -100),
                run_c=lambda n=n, reduction=reduction: c_module._aten_dispatch(
                    op, logits(n, "bfloat16")[1], targets(n)[1], None, reduction, -100),
                value_check=_nll_pair_check,
                note="at n=258 a bfloat16 partial sum has saturated (256 + 1 == 256) so "
                     "summing ones answers 256; the cast answers 258. mean divides by it, "
                     "so this case sees the difference in the loss as well",
            )
        )

    # --- a 1-D input takes the reduce path whatever `reduction` says -------
    one_d = [-1.0, -2.0, -3.0]
    for dtype_name in _NLL_DTYPES:
        for reduction, rn in [(_NLL_NONE, "none"), (_NLL_MEAN, "mean"), (_NLL_SUM, "sum")]:
            for tgt_flat, tgt_shape, ignore, label in [
                ([2], (), -100, "0-d target"),
                ([2], (1,), -100, "1-d target of size 1 -- the only 1-d size allowed"),
                ([2], (), 2, "the single target ignored: mean is 0/0"),
            ]:
                cases.append(
                    Case(
                        name=(f"nll_loss_forward(1-D input, dtype={dtype_name}, "
                              f"reduction={rn}, {label})"),
                        op=op,
                        run_torch=lambda dtype_name=dtype_name, reduction=reduction,
                                         tgt_flat=tgt_flat, tgt_shape=tgt_shape,
                                         ignore=ignore: torch_call(
                            _pair(torch_module, c_module, one_d, (3,), dtype_name)[0],
                            _pair(torch_module, c_module, tgt_flat, tgt_shape, "int64")[0],
                            None, reduction, ignore,
                        ),
                        run_c=lambda dtype_name=dtype_name, reduction=reduction,
                                     tgt_flat=tgt_flat, tgt_shape=tgt_shape,
                                     ignore=ignore: c_module._aten_dispatch(
                            op,
                            _pair(torch_module, c_module, one_d, (3,), dtype_name)[1],
                            _pair(torch_module, c_module, tgt_flat, tgt_shape, "int64")[1],
                            None, reduction, ignore,
                        ),
                        value_check=_nll_pair_check,
                        note="reduction=none produces a SCALAR for a 1-D input, and "
                             "total_weight is 1 rather than the 0 a 2-D none gives",
                    )
                )

    # --- the edges, each one a rule that is not derivable ------------------
    two = [-1.0, -2.0, -3.0, -0.5, -4.0, -0.25]
    edges = [
        ("every target ignored", [2, 2], (2,), None, 2,
         "mean is 0/0 = NaN and sum is 0.0; total_weight is 0 for both"),
        ("a target out of bounds but equal to ignore_index", [0, 77], (2,), None, 77,
         "ignore_index is tested BEFORE the bounds check, so this is legal"),
        ("all weights zero", [0, 2], (2,), [0.0] * _NLL_CLASSES, -100,
         "total_weight is 0 from a sum rather than from a count, and mean is 0/0"),
        ("uint8 target", None, None, None, -100, "Byte is the other accepted target dtype"),
        ("reduction=3, which upstream does not validate", [0, 2], (2,), None, -100,
         "anything but Mean is treated as a sum -- measured, not a guess"),
    ]
    for label, tgt, tgt_shape, w, ignore, note in edges:
        if label.startswith("uint8"):
            for reduction, rn in [(_NLL_NONE, "none"), (_NLL_MEAN, "mean"), (_NLL_SUM, "sum")]:
                cases.append(
                    Case(
                        name=f"nll_loss_forward(float32, {label}, reduction={rn})",
                        op=op,
                        run_torch=lambda reduction=reduction: torch_call(
                            _pair(torch_module, c_module, two, (2, 3), "float32")[0],
                            _pair(torch_module, c_module, [0, 2], (2,), "uint8")[0],
                            None, reduction, -100,
                        ),
                        run_c=lambda reduction=reduction: c_module._aten_dispatch(
                            op,
                            _pair(torch_module, c_module, two, (2, 3), "float32")[1],
                            _pair(torch_module, c_module, [0, 2], (2,), "uint8")[1],
                            None, reduction, -100,
                        ),
                        value_check=_nll_pair_check,
                        note=note,
                    )
                )
            continue
        for reduction, rn in [(_NLL_NONE, "none"), (_NLL_MEAN, "mean"), (_NLL_SUM, "sum")]:
            red = 3 if label.startswith("reduction=3") else reduction
            if label.startswith("reduction=3") and reduction != _NLL_NONE:
                continue
            cases.append(
                Case(
                    name=f"nll_loss_forward(float32, {label}, reduction={red})",
                    op=op,
                    run_torch=lambda tgt=tgt, tgt_shape=tgt_shape, w=w, ignore=ignore,
                                     red=red: torch_call(
                        _pair(torch_module, c_module, two, (2, 3), "float32")[0],
                        _pair(torch_module, c_module, tgt, tgt_shape, "int64")[0],
                        _pair(torch_module, c_module, w, (3,), "float32")[0] if w else None,
                        red, ignore,
                    ),
                    run_c=lambda tgt=tgt, tgt_shape=tgt_shape, w=w, ignore=ignore,
                                 red=red: c_module._aten_dispatch(
                        op,
                        _pair(torch_module, c_module, two, (2, 3), "float32")[1],
                        _pair(torch_module, c_module, tgt, tgt_shape, "int64")[1],
                        _pair(torch_module, c_module, w, (3,), "float32")[1] if w else None,
                        red, ignore,
                    ),
                    value_check=_nll_pair_check,
                    note=note,
                )
            )

    # The empty batch: mean over nothing is NaN by upstream's own decision
    # (pytorch#64572), sum over nothing is 0, and reduction=none keeps the
    # (0,) shape rather than collapsing to a scalar.
    for reduction, rn in [(_NLL_NONE, "none"), (_NLL_MEAN, "mean"), (_NLL_SUM, "sum")]:
        cases.append(
            Case(
                name=f"nll_loss_forward(float32, empty batch, reduction={rn})",
                op=op,
                run_torch=lambda reduction=reduction: torch_call(
                    _pair(torch_module, c_module, [], (0, 3), "float32")[0],
                    _pair(torch_module, c_module, [], (0,), "int64")[0],
                    None, reduction, -100,
                ),
                run_c=lambda reduction=reduction: c_module._aten_dispatch(
                    op,
                    _pair(torch_module, c_module, [], (0, 3), "float32")[1],
                    _pair(torch_module, c_module, [], (0,), "int64")[1],
                    None, reduction, -100,
                ),
                value_check=_nll_pair_check,
                note="mean over an empty batch is NaN, not 0 -- upstream chose this "
                     "deliberately and the comment in LossNLL.cpp cites the PR",
            )
        )

    # --- the refusals, each one measured on upstream -----------------------
    refusals = [
        ("3-D input", (2, 3, 4), [0, 0], (2,), None, _NLL_MEAN, -100,
         "RuntimeError: input tensor should be 1D or 2D"),
        ("0-D input", (), [0], (), None, _NLL_MEAN, -100,
         "the same message -- dim() must be > 0 as well as <= 2"),
        ("2-D target", (2, 3), [0, 1, 0, 1], (2, 2), None, _NLL_MEAN, -100,
         "RuntimeError: 0D or 1D target tensor expected, multi-target not supported"),
        ("batch size mismatch", (2, 3), [0, 1, 2], (3,), None, _NLL_MEAN, -100,
         "RuntimeError: size mismatch (got input: [2, 3], target: [3])"),
        ("target out of bounds", (2, 3), [0, 5], (2,), None, _NLL_MEAN, -100,
         "IndexError: Target 5 is out of bounds."),
        ("negative target", (2, 3), [0, -1], (2,), None, _NLL_MEAN, -100,
         "IndexError -- the bounds check is two-sided"),
        ("target out of bounds, reduction=none", (2, 3), [0, 5], (2,), None, _NLL_NONE, -100,
         "the elementwise path bounds-checks too, and that is a separate branch"),
        ("weight of the wrong size", (2, 3), [0, 2], (2,), [1.0, 2.0], _NLL_MEAN, -100,
         "RuntimeError naming the class count"),
        ("2-D weight", (2, 3), [0, 2], (2,), [1.0, 2.0, 3.0], _NLL_MEAN, -100,
         "a (1,3) weight is refused even though it has the right numel"),
        ("1-D input with a 1-D target of size 2", (3,), [0, 1], (2,), None, _NLL_MEAN, -100,
         "ValueError, not RuntimeError -- upstream uses TORCH_CHECK_VALUE here"),
    ]
    for label, in_shape, tgt, tgt_shape, w, reduction, ignore, why in refusals:
        n = 1
        for s in in_shape:
            n *= s
        w_shape = (1, 3) if label.startswith("2-D weight") else ((len(w),) if w else None)
        cases.append(
            Case(
                name=f"nll_loss_forward({label} rejected on both sides)",
                op=op,
                run_torch=lambda in_shape=in_shape, n=n, tgt=tgt, tgt_shape=tgt_shape,
                                 w=w, w_shape=w_shape, reduction=reduction,
                                 ignore=ignore: torch_call(
                    _pair(torch_module, c_module, [-1.0] * n, in_shape, "float32")[0],
                    _pair(torch_module, c_module, tgt, tgt_shape, "int64")[0],
                    _pair(torch_module, c_module, w, w_shape, "float32")[0] if w else None,
                    reduction, ignore,
                ),
                run_c=lambda in_shape=in_shape, n=n, tgt=tgt, tgt_shape=tgt_shape,
                             w=w, w_shape=w_shape, reduction=reduction,
                             ignore=ignore: c_module._aten_dispatch(
                    op,
                    _pair(torch_module, c_module, [-1.0] * n, in_shape, "float32")[1],
                    _pair(torch_module, c_module, tgt, tgt_shape, "int64")[1],
                    _pair(torch_module, c_module, w, w_shape, "float32")[1] if w else None,
                    reduction, ignore,
                ),
                expect="both_error",
                note=why,
            )
        )

    for tgt_dtype, why in [
        ("int32", "RuntimeError: expected target dtype to be Long or Byte, but got Int"),
        ("float32", "a floating target is refused -- that is the prob-target API, "
                    "which lives in cross_entropy_loss and not here"),
    ]:
        cases.append(
            Case(
                name=f"nll_loss_forward(target dtype {tgt_dtype} rejected on both sides)",
                op=op,
                run_torch=lambda tgt_dtype=tgt_dtype: torch_call(
                    _pair(torch_module, c_module, two, (2, 3), "float32")[0],
                    _pair(torch_module, c_module, [0, 2], (2,), tgt_dtype)[0],
                    None, _NLL_MEAN, -100,
                ),
                run_c=lambda tgt_dtype=tgt_dtype: c_module._aten_dispatch(
                    op,
                    _pair(torch_module, c_module, two, (2, 3), "float32")[1],
                    _pair(torch_module, c_module, [0, 2], (2,), tgt_dtype)[1],
                    None, _NLL_MEAN, -100,
                ),
                expect="both_error",
                note=why,
            )
        )

    cases.append(
        Case(
            name="nll_loss_forward(int64 input rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [0] * 6, (2, 3), "int64")[0],
                _pair(torch_module, c_module, [0, 2], (2,), "int64")[0],
                None, _NLL_MEAN, -100,
            ),
            run_c=lambda: c_module._aten_dispatch(
                op,
                _pair(torch_module, c_module, [0] * 6, (2, 3), "int64")[1],
                _pair(torch_module, c_module, [0, 2], (2,), "int64")[1],
                None, _NLL_MEAN, -100,
            ),
            expect="both_error",
            note='NotImplementedError: "nll_loss_out_frame" not implemented for \'Long\'',
        )
    )

    # The weight's dtype must match the input's *exactly* -- it is
    # `data_ptr<scalar_t>()` that raises, not a promotion rule. Both the
    # reduce path and the elementwise path go through it.
    for w_dtype, reduction, rn in [("float64", _NLL_MEAN, "mean"),
                                   ("bfloat16", _NLL_MEAN, "mean"),
                                   ("float64", _NLL_NONE, "none")]:
        cases.append(
            Case(
                name=f"nll_loss_forward(float32 input, {w_dtype} weight, reduction={rn} "
                     f"rejected on both sides)",
                op=op,
                run_torch=lambda w_dtype=w_dtype, reduction=reduction: torch_call(
                    _pair(torch_module, c_module, two, (2, 3), "float32")[0],
                    _pair(torch_module, c_module, [0, 2], (2,), "int64")[0],
                    _pair(torch_module, c_module, [1.0, 1.0, 1.0], (3,), w_dtype)[0],
                    reduction, -100,
                ),
                run_c=lambda w_dtype=w_dtype, reduction=reduction: c_module._aten_dispatch(
                    op,
                    _pair(torch_module, c_module, two, (2, 3), "float32")[1],
                    _pair(torch_module, c_module, [0, 2], (2,), "int64")[1],
                    _pair(torch_module, c_module, [1.0, 1.0, 1.0], (3,), w_dtype)[1],
                    reduction, -100,
                ),
                expect="both_error",
                note="RuntimeError: expected scalar type Float but found "
                     + ("Double" if w_dtype == "float64" else "BFloat16"),
            )
        )

    kw_t, kw_c = _pair(torch_module, c_module, two, (2, 3), "float32")
    kwt_t, kwt_c = _pair(torch_module, c_module, [0, 2], (2,), "int64")
    cases.append(
        Case(
            name="nll_loss_forward(every argument by keyword)",
            op=op,
            run_torch=lambda: torch_call(self=kw_t, target=kwt_t, weight=None,
                                         reduction=_NLL_MEAN, ignore_index=-100),
            run_c=lambda: c_module._aten_dispatch(op, self=kw_c, target=kwt_c, weight=None,
                                                  reduction=_NLL_MEAN, ignore_index=-100),
            value_check=_nll_pair_check,
        )
    )

    # --- the spellings -----------------------------------------------------
    #
    # `torch._C._nn.nll_loss_forward` is deliberately NOT among them: upstream
    # has no such name (`hasattr` is False on 2.13.0), and the shim must not
    # invent one. The three that do exist are all
    # `CompositeImplicitAutograd`, so none of them appears in the dispatch
    # trace that named this op -- which is the §1 finding, checked here.
    F_t = torch_module.nn.functional
    spellings = [
        ("torch._C._nn.nll_loss",
         lambda t, tt: torch_module._C._nn.nll_loss(t, tt, None, _NLL_MEAN, -100),
         lambda c, ct: c_module._nn.nll_loss(c, ct, None, _NLL_MEAN, -100)),
        ("torch._C._nn.nll_loss_nd",
         lambda t, tt: torch_module._C._nn.nll_loss_nd(t, tt, None, _NLL_MEAN, -100),
         lambda c, ct: c_module._nn.nll_loss_nd(c, ct, None, _NLL_MEAN, -100)),
        ("torch._C._nn.cross_entropy_loss",
         lambda t, tt: torch_module._C._nn.cross_entropy_loss(t, tt, None, _NLL_MEAN, -100, 0.0),
         lambda c, ct: c_module._nn.cross_entropy_loss(c, ct, None, _NLL_MEAN, -100, 0.0)),
        ("torch._C._nn.cross_entropy_loss(reduction=sum)",
         lambda t, tt: torch_module._C._nn.cross_entropy_loss(t, tt, None, _NLL_SUM, -100, 0.0),
         lambda c, ct: c_module._nn.cross_entropy_loss(c, ct, None, _NLL_SUM, -100, 0.0)),
        ("torch._C._nn.cross_entropy_loss(reduction=none)",
         lambda t, tt: torch_module._C._nn.cross_entropy_loss(t, tt, None, _NLL_NONE, -100, 0.0),
         lambda c, ct: c_module._nn.cross_entropy_loss(c, ct, None, _NLL_NONE, -100, 0.0)),
        ("torch._C._nn.cross_entropy_loss(ignore_index=2)",
         lambda t, tt: torch_module._C._nn.cross_entropy_loss(t, tt, None, _NLL_MEAN, 2, 0.0),
         lambda c, ct: c_module._nn.cross_entropy_loss(c, ct, None, _NLL_MEAN, 2, 0.0)),
    ]
    for label, fn_t, fn_c in spellings:
        cases.append(
            Case(
                name=f"nll_loss_forward via {label}",
                op=op,
                run_torch=lambda fn_t=fn_t: fn_t(
                    _pair(torch_module, c_module, two, (2, 3), "float32")[0],
                    _pair(torch_module, c_module, [0, 2], (2,), "int64")[0]),
                run_c=lambda fn_c=fn_c: fn_c(
                    _pair(torch_module, c_module, two, (2, 3), "float32")[1],
                    _pair(torch_module, c_module, [0, 2], (2,), "int64")[1]),
                note="a CompositeImplicitAutograd name -- invisible to the dispatch "
                     "trace that found this op, and the reason the op scan under-counted",
            )
        )
    # And a 1-D input through `nll_loss_nd`, which is the branch that routes to
    # `nll_loss` rather than to `nll_loss2d`.
    cases.append(
        Case(
            name="nll_loss_forward via torch._C._nn.nll_loss_nd(1-D input)",
            op=op,
            run_torch=lambda: torch_module._C._nn.nll_loss_nd(
                _pair(torch_module, c_module, one_d, (3,), "float32")[0],
                _pair(torch_module, c_module, [2], (), "int64")[0], None, _NLL_MEAN, -100),
            run_c=lambda: c_module._nn.nll_loss_nd(
                _pair(torch_module, c_module, one_d, (3,), "float32")[1],
                _pair(torch_module, c_module, [2], (), "int64")[1], None, _NLL_MEAN, -100),
        )
    )
    assert F_t is not None
    return cases


# --- aten._safe_softmax.default -----------------------------------------
# torch's own decomposition (`torch/_decomp/decompositions.py::safe_softmax`):
# `out = softmax(self, dim); masked = all(self == -inf, dim); where(masked, 0, out)`.
# The one place this disagrees with `_softmax.default` (`softmax_cases`
# above) is a row that is *entirely* -inf: plain softmax gives NaN there
# (0/0 from `-inf - (-inf)`), `_safe_softmax` gives a clean 0 -- exactly the
# shape of a fully-masked attention row. Both re-measured against torch
# 2.13.0 below rather than trusted from the kernel's own doc comment.


def safe_softmax_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten._safe_softmax.default"
    cases: list[Case] = []
    scenarios = [
        ([1.0, 2.0, 3.0, 0.0, 0.0, 0.0], (2, 3), -1, "last dim -- the vectorised path"),
        ([1.0, 2.0, 3.0, 0.0, 0.0, 0.0], (2, 3), 0, "first dim -- the strided path"),
        ([1.0, 2.0, 3.0], (3,), 0, "1-D"),
        ([3.0], (), -1, "0-d: the single element is the whole distribution, so 1.0"),
    ]
    for dtype_name in _SOFTMAX_DTYPES:
        for flat, shape, dim, note in scenarios:
            cases.append(
                Case(
                    name=f"_safe_softmax(dtype={dtype_name}, shape={shape}, dim={dim}) [{note}]",
                    op=op,
                    run_torch=lambda flat=flat, shape=shape, dim=dim, dtype_name=dtype_name: torch_call(
                        _pair(torch_module, c_module, flat, shape, dtype_name)[0], dim
                    ),
                    run_c=lambda flat=flat, shape=shape, dim=dim, dtype_name=dtype_name: c_module._aten_dispatch(
                        op, _pair(torch_module, c_module, flat, shape, dtype_name)[1], dim
                    ),
                    note=note,
                )
            )

    # The divergence from `_softmax.default` this op exists for: a fully
    # -inf row gives a clean 0 (not NaN), while a partially-masked row still
    # matches plain softmax (the max-subtraction already makes that one
    # safe). Both measured against real torch.
    edge = [
        ([1.0, float("-inf"), 2.0], (3,), "one masked position -- same as plain softmax here"),
        ([float("-inf"), float("-inf")], (2,), "a fully masked row -- 0, not NaN (the divergence)"),
        ([float("-inf"), float("-inf"), float("-inf")], (1, 3), "fully masked, batched over dim 0"),
        ([1.0, 2.0, float("-inf"), float("-inf")], (2, 2), "one masked row, one live row, same call"),
        ([1000.0, 1001.0, 999.0], (3,), "large logits -- max subtraction still applies"),
    ]
    for flat, shape, note in edge:
        cases.append(
            Case(
                name=f"_safe_softmax(float32, {shape}) [{note}]",
                op=op,
                run_torch=lambda flat=flat, shape=shape: torch_call(
                    _pair(torch_module, c_module, flat, shape, "float32")[0], -1
                ),
                run_c=lambda flat=flat, shape=shape: c_module._aten_dispatch(
                    op, _pair(torch_module, c_module, flat, shape, "float32")[1], -1
                ),
                note=note,
            )
        )

    # `dtype` casts *before* the integral refusal runs -- measured:
    # _safe_softmax(int64_tensor, 0, torch.float32) succeeds, unlike plain
    # _softmax which has no dtype-cast path exercised here at all.
    cases.append(
        Case(
            name="_safe_softmax(int64 input, dtype=float32 -- casts before the integral refusal)",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [1, 2, 3], (3,), "int64")[0], 0,
                dt.torch_dtype(torch_module, "float32"),
            ),
            run_c=lambda: c_module._aten_dispatch(
                op, _pair(torch_module, c_module, [1, 2, 3], (3,), "int64")[1], 0,
                dt.c_dtype(c_module, "float32"),
            ),
            note="dtype casts self before the floating-point check runs, so this succeeds "
                 "even though a bare int64 input (below) is refused",
        )
    )
    cases.append(
        Case(
            name="_safe_softmax(int64 rejected on both sides)",
            op=op,
            run_torch=lambda: torch_call(_pair(torch_module, c_module, [1, 2, 3], (3,), "int64")[0], -1),
            run_c=lambda: c_module._aten_dispatch(
                op, _pair(torch_module, c_module, [1, 2, 3], (3,), "int64")[1], -1
            ),
            expect="both_error",
            note='torch: NotImplementedError, "softmax_lastdim_kernel_impl" not implemented for \'Long\'',
        )
    )
    return cases


# --- aten.add_.Tensor -----------------------------------------------------
# The in-place sibling of `add.Tensor`, needed for falcon's residual
# connections (`hidden_states += attn_output`, which traces to this
# overload rather than a rebind). Fresh operands per case, same as
# fill__cases/copy__cases above (the module note on in-place ops) --
# sharing an operand across cases would carry one case's mutation into the
# next.
#
# Two real gaps came out of re-measuring the kernel's own doc comment
# against actual torch 2.13.0 (see the block comment above `_baddbmm_case`
# for the other one):
#
#   * `int32.add_(float32_tensor)` -- upstream refuses ("result type Float
#     can't be cast to the desired output type Int"); the shim casts
#     `other` into the receiver's dtype and computes. `torch_error`.
#   * `bool.add_(bool)` -- upstream computes a logical or (`[True,False]
#     .add_([True,True])` -> `[True,True]`, measured); the shim refuses
#     unconditionally. `c_error`, not the `both_error` the kernel's doc
#     comment implies (it matches `add.Tensor`'s *own* refusal, not
#     upstream's actual behaviour).


def add__tensor_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.add_.Tensor"
    cases: list[Case] = []
    for dtype_name in ["float64", "float32", "float16", "bfloat16", "int64", "int32", "uint8"]:
        dst_t, dst_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (2, 2), dtype_name)
        src_t, src_c = pair_from_flat(torch_module, c_module, [10, 20, 30, 40], (2, 2), dtype_name)
        cases.append(
            Case(
                name=f"add_(dtype={dtype_name}, same shape)",
                op=op,
                run_torch=lambda dst_t=dst_t, src_t=src_t: torch_call(dst_t, src_t),
                run_c=lambda dst_c=dst_c, src_c=src_c: c_module._aten_dispatch(op, dst_c, src_c),
                note="in-place: compares the mutated dst operand add_ returns",
            )
        )

    for dtype_name, alpha, note in [
        ("float32", 2.0, "alpha scales other before it's added"),
        ("float32", -1.0, "negative alpha -- effectively an in-place subtract"),
        ("int32", 3, "integer alpha"),
    ]:
        dst_t, dst_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (2, 2), dtype_name)
        src_t, src_c = pair_from_flat(torch_module, c_module, [10, 20, 30, 40], (2, 2), dtype_name)
        cases.append(
            Case(
                name=f"add_(dtype={dtype_name}, alpha={alpha}) [{note}]",
                op=op,
                run_torch=lambda dst_t=dst_t, src_t=src_t, alpha=alpha: torch_call(dst_t, src_t, alpha=alpha),
                run_c=lambda dst_c=dst_c, src_c=src_c, alpha=alpha: c_module._aten_dispatch(op, dst_c, src_c, alpha=alpha),
                note=note,
            )
        )

    dst2_t, dst2_c = pair_from_flat(torch_module, c_module, [0, 0, 0, 0], (2, 2), "float32")
    src2_t, src2_c = pair_from_flat(torch_module, c_module, [9, 8], (1, 2), "float32")
    cases.append(
        Case(
            name="add_(dtype=float32, broadcast src)",
            op=op,
            run_torch=lambda: torch_call(dst2_t, src2_t),
            run_c=lambda: c_module._aten_dispatch(op, dst2_c, src2_c),
            note="src (1,2) broadcasts to fill dst (2,2) in place",
        )
    )

    # The two measured gaps -- see the module note above.
    int32_dst_t, int32_dst_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (2, 2), "int32")
    float_src_t, float_src_c = pair_from_flat(torch_module, c_module, [1.5, 2.5, 3.5, 4.5], (2, 2), "float32")
    cases.append(
        Case(
            name="add_(dtype=int32, other=float32) [refused on BOTH sides -- was a gap]",
            op=op,
            run_torch=lambda: torch_call(int32_dst_t, float_src_t),
            run_c=lambda: c_module._aten_dispatch(op, int32_dst_c, float_src_c),
            expect="both_error",
            note="'result type Float can't be cast to the desired output type Int'. This was "
                 "expect='torch_error' until docs/ARCH20.md §8.3: the shim used to cast `other` "
                 "down into the receiver's dtype and return a truncated answer where upstream "
                 "raises. `inplace_cast_check` refuses it now, so the two agree",
        )
    )
    bool_dst_t, bool_dst_c = pair_from_flat(torch_module, c_module, [1, 0], (2,), "bool")
    bool_src_t, bool_src_c = pair_from_flat(torch_module, c_module, [1, 1], (2,), "bool")
    cases.append(
        Case(
            name="add_(dtype=bool -- torch computes a logical or, c refuses)",
            op=op,
            run_torch=lambda: torch_call(bool_dst_t, bool_src_t),
            run_c=lambda: c_module._aten_dispatch(op, bool_dst_c, bool_src_c),
            expect="c_error",
            note="torch: [True,False].add_([True,True]) -> [True,True] (logical or, measured); "
                 "the shim's blanket bool refusal in arith_tag over-refuses here",
        )
    )
    cases.extend(add__member_cases(torch_module, c_module))
    cases.extend(
        c for c in _view_write_cases(torch_module, c_module)
        if c.op == "aten.add_.Tensor"
    )
    return cases


# --- aten.mul.Scalar -------------------------------------------------------
# `wrapped_scalar_tensor`'s counterpart to `mul.Tensor` -- reached only when
# the *parser* keeps the RHS as a `Scalar` rather than promoting it to a 0-d
# tensor first (see `arith_scalar`'s own doc comment). The promotion rule is
# `arith_tag`'s, the same one `rsub_scalar_cases` already pins for
# `rsub.Scalar`: an integral tensor stays integral under an int scalar and
# promotes to the default float under a float one.


def mul_scalar_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.mul.Scalar"
    cases: list[Case] = []
    for dtype_name in _MUL_DIV_FLOAT_DTYPES:
        a_t, a_c = pair_from_flat(torch_module, c_module, [1.0, -2.0, 0.0, 3.5], (2, 2), dtype_name)
        for scalar, note in [
            (2.0, "plain scalar multiply"),
            (0.0, "multiply by zero"),
            (-1.5, "negative scalar"),
        ]:
            cases.append(
                Case(
                    name=f"mul.Scalar(dtype={dtype_name}, other={scalar}) [{note}]",
                    op=op,
                    run_torch=lambda a_t=a_t, scalar=scalar: torch_call(a_t, scalar),
                    run_c=lambda a_c=a_c, scalar=scalar: c_module._aten_dispatch(op, a_c, scalar),
                    note=note,
                )
            )

    # The "wrapped number" dtype rule: an integral tensor stays integral
    # under an int scalar and promotes to the default float under a float
    # one -- re-measured here rather than assumed from rsub.Scalar's case.
    for dtype_name, flat, scalar, note in [
        ("int64", [1, 2, 3, 4], 5, "int tensor, int scalar -> int64"),
        ("int64", [1, 2, 3, 4], 5.0, "int tensor, FLOAT scalar -> float32"),
        ("int32", [1, 2, 3, 4], -3, "negative int scalar"),
        ("int16", [10, 20, 30, 40], 2, "int16 * int scalar"),
        ("uint8", [80, 90, 100, 110], 3, "uint8 wraps mod 256: 90*3=270 -> 14, 100*3=300 -> 44"),
    ]:
        a_t, a_c = pair_from_flat(torch_module, c_module, flat, (2, 2), dtype_name)
        cases.append(
            Case(
                name=f"mul.Scalar(dtype={dtype_name}, other={scalar!r}) [{note}]",
                op=op,
                run_torch=lambda a_t=a_t, scalar=scalar: torch_call(a_t, scalar),
                run_c=lambda a_c=a_c, scalar=scalar: c_module._aten_dispatch(op, a_c, scalar),
                note=note,
            )
        )

    # The measured gap: upstream computes `bool * scalar` arithmetically
    # (True/False read as 1/0, promoted exactly like any other integral
    # tensor -- int scalar keeps int64, float scalar gives float32). The
    # shim's `arith_tag` refuses every bool tensor unconditionally, which is
    # right for `mul.Tensor` (upstream's bool `*` there really is a logical
    # and) but wrong here. `c_error`, re-measured rather than assumed.
    bool_t, bool_c = pair_from_flat(torch_module, c_module, [1, 0, 1], (3,), "bool")
    cases.append(
        Case(
            name="mul.Scalar(dtype=bool, other=3 -- torch computes arithmetically, c refuses)",
            op=op,
            run_torch=lambda: torch_call(bool_t, 3),
            run_c=lambda: c_module._aten_dispatch(op, bool_c, 3),
            expect="c_error",
            note="torch: bool*3 -> tensor([3,0,3], dtype=int64) (arithmetic, not logical); "
                 "the shim's blanket bool refusal in arith_tag over-refuses the .Scalar overload",
        )
    )
    bool_float_t, bool_float_c = pair_from_flat(torch_module, c_module, [1, 0, 1], (3,), "bool")
    cases.append(
        Case(
            name="mul.Scalar(dtype=bool, other=2.5 -- float scalar promotes to float32)",
            op=op,
            run_torch=lambda: torch_call(bool_float_t, 2.5),
            run_c=lambda: c_module._aten_dispatch(op, bool_float_c, 2.5),
            expect="c_error",
            note="torch: bool*2.5 -> tensor([2.5,0.,2.5], dtype=float32); same gap, float scalar",
        )
    )
    # The blind spot docs/TRAIN.md §5 predicted and docs/SCALAR.md fixed: every
    # scalar above (2.0, 0.0, -1.5) is exactly representable in float16 and
    # bfloat16, so this builder passed while the kernel narrowed a scalar
    # upstream widens.
    cases.extend(
        _scalar_rule_cases(
            torch_module, c_module, op,
            lambda t, s: torch_call(t, s),
            lambda c, s: c_module._aten_dispatch(op, c, s),
            rule="widen",
            why="mul_kernel's reduced-float branch reads "
                "original_scalar_value<opmath_t>(2), the un-narrowed Scalar",
        )
    )
    return cases


# --- mamba / mixtral -- the last two of the 20 measured architectures ------
# (docs/OPS4.md) with anything unimplemented. Every rule pinned below was
# re-measured against torch 2.13.0 with a real `TorchDispatchMode` over
# `transformers` 5.15.1 rather than copied from a kernel's doc comment --
# docs/OPS4.md's own note is that doc comments have been wrong about
# upstream three times before.


def exp_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.exp.default"
    cases: list[Case] = []
    scenarios = [
        ([0.0, 1.0, -1.0, 2.0, -2.0], (5,), "assorted"),
        ([0.0], (), "0-d"),
        ([float("nan"), float("inf"), float("-inf")], (3,), "NaN/+-inf -- nan, inf, 0.0"),
        # Overflows to +inf and underflows to 0.0 in every floating dtype
        # tested here -- not the mamba-relevant range (mamba's A_log stays
        # small), but exercising the boundary rather than assuming a naive
        # `exp` implementation gets it right.
        ([-1000.0, 1000.0], (2,), "far outside range -- underflow to 0.0, overflow to inf"),
    ]
    for dtype_name in _TANH_DTYPES:
        for flat, shape, note in scenarios:
            cases.append(_unary_case(torch_module, c_module, op, torch_call, dtype_name, flat, shape, note))
    # The promotion rule, which is `cos`/`sin`/`tanh`'s and not `silu`'s: an
    # integral input gives float32 rather than raising. `mamba`'s `A =
    # -exp(A_log)` always calls with `A_log` already `float32`, but the rule
    # is re-measured here rather than assumed from the other unary ops.
    for dtype_name in _TANH_PROMOTING_DTYPES:
        cases.append(
            _unary_case(
                torch_module, c_module, op, torch_call, dtype_name, [0, 1, 2, 3], (2, 2),
                "integral input promotes to the default float, same rule as tanh/cos/sin",
            )
        )
    return cases


def erf_cases(torch_module, c_module, torch_call) -> list[Case]:
    """`aten.erf(Tensor self)` -- `sew_d`'s wall after `group_norm`.

    DeBERTa's GELU (which `sew_d` inherits) spells the error function out --
    `x * 0.5 * (1 + erf(x / sqrt(2)))` -- rather than calling `aten.gelu`, so
    the op fires on its own. Measured firing on `(1, 19, 37)` twice per
    forward.

    A plain member of the `unary_float` family, and that was measured rather
    than assumed: `int64`, `int32`, `uint8` and `bool` all give `float32`, and
    each float dtype keeps its own. `silu`, the other activation-shaped op,
    *refuses* an integral input -- so which of the two rules applies is not
    derivable from "it is an activation".

    The saturating ends are what a rational-approximation implementation gets
    wrong: `erf(inf)` is exactly `1.0`, `erf(-inf)` is exactly `-1.0`, and
    `erf(-0.0)` is `-0.0` and not `+0.0`."""
    op = "aten.erf.default"
    cases: list[Case] = []
    scenarios = [
        ([0.0, 0.5, 1.0, -1.0, 2.0, -2.0], (6,), "assorted, across the steep part"),
        ([0.0], (), "0-d"),
        ([], (0,), "empty"),
        ([float("nan"), float("inf"), float("-inf")], (3,),
         "NaN propagates; +-inf saturate to exactly +-1"),
        ([-6.0, 6.0], (2,), "far into the tails -- exactly -1 and 1"),
        ([1e-8, -1e-8], (2,), "near zero, where erf is ~2x/sqrt(pi)"),
    ]
    for dtype_name in _TANH_DTYPES:
        for flat, shape, note in scenarios:
            cases.append(
                _unary_case(torch_module, c_module, op, torch_call, dtype_name,
                            flat, shape, note))
        # `erf(-0.0)` is `-0.0`, and `-0.0 == 0.0` in Python, so this needs the
        # sign bit rather than the value -- `sqrt`'s comparator, reused.
        #
        # The four values are chosen so that `_signed_zero_check` -- an
        # *exact* comparator -- can be used at all. candle's `erf` is
        # `libm::erf` and lands 1.2e-07 from upstream's own kernel at `x = 1`
        # (`gelu_default` in aten.rs records the same divergence at
        # 4.47e-08), so an exact comparator on ordinary values fails on the
        # erf rather than on the sign bit. `erf` of `+-0.0` and `+-inf` is
        # exact on both sides -- `-0.0`, `+0.0`, `-1.0`, `+1.0` -- so this
        # case isolates the one property a tolerant comparator cannot see.
        z_t, z_c = pair_from_flat(
            torch_module, c_module,
            [-0.0, 0.0, float("-inf"), float("inf")], (2, 2), dtype_name)
        cases.append(
            Case(
                name=f"erf(dtype={dtype_name}) [-0.0 keeps its sign]",
                op=op,
                run_torch=lambda z_t=z_t: torch_call(z_t),
                run_c=lambda z_c=z_c: c_module._aten_dispatch(op, z_c),
                value_check=_signed_zero_check,
                note="measured: erf(-0.0) is -0.0, and a value comparison cannot see it",
            )
        )
    # The promotion half -- `unary_float`'s rule, not `silu`'s refusal.
    for dtype_name in _TANH_PROMOTING_DTYPES:
        cases.append(
            _unary_case(
                torch_module, c_module, op, torch_call, dtype_name, [0, 1, 2, 3], (2, 2),
                "integral input promotes to the default float; silu refuses the same input",
            )
        )
    for spelling, call in (("torch.erf(x)", lambda m, a: _free(m, "erf")(a)),
                           ("x.erf()", lambda m, a: a.erf())):
        pair = pair_from_flat(
            torch_module, c_module, [0.0, 0.5, -0.5, 2.0], (2, 2), "float32")
        cases.append(
            _member_case(
                torch_module, c_module, op, f"spelling {spelling}", "float32",
                [pair], call, note="the two doors onto the same kernel",
            )
        )
    return cases


_AVG_POOL_DTYPES = ["float64", "float32", "float16", "bfloat16"]
# 4x5, not square, and not a smooth ramp along one axis -- a kernel that
# transposed H and W, or that used one axis's stride for both, has to produce a
# different number rather than the same number by symmetry.
_AP_INPUT = [float((i * 7) % 19) - 6.0 for i in range(20)]


def _avg_pool_case(
    torch_module, c_module, torch_call, dtype_name, flat, shape, kernel,
    stride=None, padding=None, ceil_mode=False, count_include_pad=True,
    divisor_override=None, expect="match", note="",
) -> Case:
    op = "aten.avg_pool2d.default"
    x_t, x_c = pair_from_flat(torch_module, c_module, flat, shape, dtype_name)
    args = [kernel, [] if stride is None else stride,
            [0, 0] if padding is None else padding,
            ceil_mode, count_include_pad, divisor_override]
    return Case(
        name=(
            f"avg_pool2d(dtype={dtype_name}, shape={shape}, kernel={kernel}, "
            f"stride={stride}, padding={padding}, ceil={ceil_mode}, "
            f"cip={count_include_pad}, divisor={divisor_override}) [{note}]"
        ),
        op=op,
        run_torch=lambda: torch_call(x_t, *args),
        run_c=lambda: c_module._aten_dispatch(op, x_c, *args),
        expect=expect,
        note=note,
    )


def avg_pool2d_cases(torch_module, c_module, torch_call) -> list[Case]:
    """`aten.avg_pool2d` -- `sew_d`'s wall after `sign`, reached through the
    `avg_pool1d` composite.

    The plausible wrong implementations, and what separates each:

      * **dividing by the elements actually summed, always** -- that is
        `count_include_pad=False`. With padding and `count_include_pad=True`
        upstream divides by the *padded* window area instead: measured, the
        cell summing `1+2 = 3` gives `0.75` one way and `1.5` the other. Same
        sum, same window, two answers, and the default is the first.
      * **`stride` defaulting to 1** -- upstream's `int[1] stride=[]` means
        "the kernel size". A `stride=None` case is here beside the explicit
        one so the two must agree.
      * **`ceil_mode` without the drop rule** -- `ceil` can produce a last
        window that starts at or past the end of the padded input, and
        upstream drops it. Cased on a `1x5` where `ceil` and `floor` differ.
      * **rounding or flooring the integral divide** -- `int64` truncates
        toward zero: `-11/4` is `-2`, not `-3`.
      * **`float32` accumulated in `f64`** -- measured 1.43e-05 relative from
        upstream, past this harness's `float32` tolerance. The reduced dtypes
        go the *other* way (bit-identical through `f32`), so the pair of them
        is what pins the accumulate type.
    """
    op = "aten.avg_pool2d.default"
    cases: list[Case] = []

    for dtype_name in _AVG_POOL_DTYPES:
        for kernel, stride, padding, ceil, cip, note in (
            ([2, 2], [2, 2], None, False, True, "the plain case"),
            ([2, 2], None, None, False, True, "stride defaults to the KERNEL, not to 1"),
            ([2, 2], [2, 2], None, True, True, "ceil_mode adds a partial column"),
            ([2, 2], [2, 2], [1, 1], False, True, "padding, counted IN the divisor"),
            ([2, 2], [2, 2], [1, 1], False, False, "padding, counted OUT of the divisor"),
            ([3, 3], [1, 1], [1, 1], True, False, "overlapping windows, ceil, cip=False"),
            ([1, 2], [1, 2], None, False, True, "sew_d's own geometry: a degenerate H axis"),
            ([2, 1], [2, 1], None, False, True, "...and its transpose, which must differ"),
            ([4, 5], [1, 1], None, False, True, "one window covering everything"),
            ([2, 3], [1, 2], None, False, True, "asymmetric kernel and stride"),
        ):
            cases.append(
                _avg_pool_case(
                    torch_module, c_module, torch_call, dtype_name, _AP_INPUT, (1, 1, 4, 5),
                    kernel, stride, padding, ceil, cip, note=note,
                )
            )
        # Several planes, so a kernel that pooled one and repeated it fails.
        cases.append(
            _avg_pool_case(
                torch_module, c_module, torch_call, dtype_name,
                [float((i * 11) % 23) - 8.0 for i in range(2 * 3 * 4 * 5)], (2, 3, 4, 5),
                [2, 2], [2, 2], note="N=2, C=3: six distinct planes",
            )
        )
        # Rank 3 -- `avg_pool2d` accepts (C, H, W) as well as (N, C, H, W).
        cases.append(
            _avg_pool_case(
                torch_module, c_module, torch_call, dtype_name, _AP_INPUT, (1, 4, 5),
                [2, 2], [2, 2], note="rank 3 (C,H,W), no batch axis",
            )
        )

    # `divisor_override` replaces the divisor outright, padded or not.
    for divisor, note in ((5, "an override larger than the window"),
                          (1, "an override of 1 makes this a sum"),
                          (-2, "a negative override is accepted")):
        cases.append(
            _avg_pool_case(
                torch_module, c_module, torch_call, "float32", _AP_INPUT, (1, 1, 4, 5),
                [2, 2], [2, 2], divisor_override=divisor, note=note,
            )
        )
    cases.append(
        _avg_pool_case(
            torch_module, c_module, torch_call, "float32", _AP_INPUT, (1, 1, 4, 5),
            [2, 2], [2, 2], [1, 1], False, True, divisor_override=3,
            note="an override wins over count_include_pad",
        )
    )

    # `ceil_mode`'s drop rule, on the geometry where ceil and floor differ.
    row = [0.0, 1.0, 2.0, 3.0, 4.0]
    for ceil, note in ((True, "ceil keeps a 1-element last window"),
                       (False, "floor drops it")):
        cases.append(
            _avg_pool_case(
                torch_module, c_module, torch_call, "float32", row, (1, 1, 1, 5),
                [1, 2], [1, 2], ceil_mode=ceil, note=note,
            )
        )
    cases.append(
        _avg_pool_case(
            torch_module, c_module, torch_call, "float32", row, (1, 1, 1, 5),
            [1, 3], [1, 2], [0, 1], True, False,
            note="ceil + padding + cip=False, all three interacting",
        )
    )

    # `int64` computes and truncates toward zero; every other integral dtype
    # and `bool` raise. Measured one at a time -- "integral is supported" would
    # have been the wrong summary.
    for flat, note in (([1, 2, 3, 5], "sum 11 over 4 -> 2, not 2.75 and not 3"),
                       ([-1, -2, -3, -5], "sum -11 over 4 -> -2, not -3 (truncation, not floor)")):
        cases.append(
            _avg_pool_case(
                torch_module, c_module, torch_call, "int64", flat, (1, 1, 2, 2),
                [2, 2], [2, 2], note=note,
            )
        )
    for dtype_name in ("int32", "uint8", "bool"):
        flat = [1] * 20 if dtype_name == "bool" else [int(v) + 6 for v in _AP_INPUT]
        cases.append(
            _avg_pool_case(
                torch_module, c_module, torch_call, dtype_name, flat, (1, 1, 4, 5),
                [2, 2], [2, 2], expect="both_error",
                note='"avg_pool2d" not implemented for this dtype -- only int64 among the integrals',
            )
        )

    # The refusals.
    for kernel, stride, padding, divisor, note in (
        ([2, 2], [2, 2], [2, 2], None, "padding greater than half the kernel"),
        ([2, 2], [0, 0], None, None, "a zero stride"),
        ([9, 9], [1, 1], None, None, "a kernel larger than the input"),
        ([2, 2], [2, 2], None, 0, "divisor_override of zero"),
    ):
        cases.append(
            _avg_pool_case(
                torch_module, c_module, torch_call, "float32", _AP_INPUT, (1, 1, 4, 5),
                kernel, stride, padding, divisor_override=divisor,
                expect="both_error", note=note,
            )
        )
    cases.append(
        _avg_pool_case(
            torch_module, c_module, torch_call, "float32", [1.0, 2.0], (2,),
            [2, 2], [2, 2], expect="both_error", note="rank 1 is neither 3 nor 4",
        )
    )

    # Keyword coverage.
    kw_t, kw_c = pair_from_flat(torch_module, c_module, _AP_INPUT, (1, 1, 4, 5), "float32")
    cases.append(
        Case(
            name="avg_pool2d(self=/kernel_size=/stride=/padding=/ceil_mode=/"
                 "count_include_pad=/divisor_override= all by keyword)",
            op=op,
            run_torch=lambda: torch_call(
                self=kw_t, kernel_size=[2, 2], stride=[2, 2], padding=[1, 1],
                ceil_mode=False, count_include_pad=False, divisor_override=None),
            run_c=lambda: c_module._aten_dispatch(
                op, self=kw_c, kernel_size=[2, 2], stride=[2, 2], padding=[1, 1],
                ceil_mode=False, count_include_pad=False, divisor_override=None),
        )
    )

    cases.extend(_avg_pool1d_cases(torch_module, c_module))
    return cases


def _avg_pool1d_cases(torch_module, c_module) -> list[Case]:
    """`torch.avg_pool1d` -- the composite `sew_d` actually spells.

    `aten::avg_pool1d` is `CompositeImplicitAutograd` over `unsqueeze(-2)`,
    `avg_pool2d([1,k],[1,s])`, `squeeze(-2)`. Golden compares by dispatch key
    and is blind to the whole derivation -- in particular to which axis gets
    the degenerate `1`.

    `stride=None` is here as well as an explicit stride because upstream's
    default is the *kernel size*, and a composite that passed `1` through would
    give a longer output for every default call, including `sew_d`'s.
    """
    op = "aten.avg_pool2d.default"
    cases: list[Case] = []
    flat = [float((i * 7) % 19) - 6.0 for i in range(2 * 3 * 12)]
    for kernel, stride, padding, ceil, cip, label in (
        (2, 2, 0, False, True, "sew_d's own call: k=2 s=2"),
        (3, None, 0, False, True, "stride=None means the KERNEL, not 1"),
        (3, 2, 1, False, True, "padding, counted in"),
        (3, 2, 1, False, False, "padding, counted out"),
        (3, 2, 0, True, True, "ceil_mode"),
        (1, 1, 0, False, True, "the identity"),
    ):
        pair = pair_from_flat(torch_module, c_module, flat, (2, 3, 12), "float32")
        cases.append(
            _member_case(
                torch_module, c_module, op,
                f"composite torch.avg_pool1d({label})", "float32", [pair],
                lambda m, x, k=kernel, s=stride, p=padding, c=ceil, i=cip:
                    _free(m, "avg_pool1d")(x, k, s, p, c, i),
                note="nn.AvgPool1d's own call shape; the degenerate axis is H, not W",
            )
        )
    return cases


def log2_cases(torch_module, c_module, torch_call) -> list[Case]:
    """`aten.log2(Tensor self)` -- `sam3_video`'s wall after `div`'s promotion.

    The dtype rule is `unary_float`'s (`int64`/`uint8`/`bool` all give
    `float32`); the computation is not the family's, because candle has no
    `log2` and `log(x) / ln(2)` is a different function at the last bit --
    measured, it disagrees with `torch.log2` on 2 of 7 `float64` probe points.
    The powers of two are the cases that show it: `log2(8.0)` must be exactly
    `3.0`.
    """
    op = "aten.log2.default"
    cases: list[Case] = []
    for dtype_name in _TANH_DTYPES:
        for flat, shape, note in (
            ([1.0, 2.0, 4.0, 8.0, 16.0], (5,), "exact powers of two -- must be exact"),
            ([3.0, 5.0, 10.0, 0.1], (4,), "not powers of two"),
            ([0.0], (1,), "log2(0) is -inf"),
            ([-1.0, -0.0], (2,), "negative is NaN; -0.0 is -inf"),
            ([float("inf"), float("nan")], (2,), "inf stays inf, NaN propagates"),
            ([2.0], (), "0-d"),
            ([], (0,), "empty"),
        ):
            cases.append(
                _unary_case(torch_module, c_module, op, torch_call, dtype_name,
                            flat, shape, note))
    for dtype_name in _TANH_PROMOTING_DTYPES:
        flat = [0, 1] if dtype_name == "bool" else [1, 2, 4, 8]
        cases.append(
            _unary_case(
                torch_module, c_module, op, torch_call, dtype_name, flat, (len(flat),),
                "integral input promotes to the default float",
            )
        )
    # **The case that separates `log2` from `log(x)/ln(2)`.** The sabotage run
    # for this section (docs/KERNELS26.md §25, fault S12) found that every
    # case above passes with the division: at `float64` the two differ by
    # 1 ULP, which the harness's `float64` tolerance absorbs, and the powers of
    # two are exact both ways. So the difference has to be compared *exactly*,
    # and on the values where it actually occurs -- measured on 2.13.0, the
    # division differs from `torch.log2` at 3, 9, 10, 12 and 100 in `float64`
    # and at 0.3 in `float32`.
    for dtype_name, flat in (
        ("float64", [3.0, 9.0, 10.0, 12.0, 100.0, 2.0, 4.0, 8.0]),
        ("float32", [0.3, 3.0, 10.0, 100.0]),
    ):
        e_t, e_c = pair_from_flat(
            torch_module, c_module, flat, (len(flat),), dtype_name)
        cases.append(
            Case(
                name=f"log2(dtype={dtype_name}, the values log(x)/ln(2) gets wrong) [BIT-EXACT]",
                op=op,
                run_torch=lambda e_t=e_t: torch_call(e_t),
                run_c=lambda e_c=e_c: c_module._aten_dispatch(op, e_c),
                value_check=_bitwise_equal_check,
                note="a 1-ULP difference the default tolerance cannot see; "
                     "`std::log2` is not `log` then a divide",
            )
        )
    for spelling, call in (("torch.log2(x)", lambda m, a: _free(m, "log2")(a)),
                           ("x.log2()", lambda m, a: a.log2())):
        pair = pair_from_flat(
            torch_module, c_module, [1.0, 2.0, 4.0, 8.0], (2, 2), "float32")
        cases.append(
            _member_case(
                torch_module, c_module, op, f"spelling {spelling}", "float32",
                [pair], call, note="the two doors onto the same kernel",
            )
        )
    return cases


def leaky_relu_cases(torch_module, c_module, torch_call) -> list[Case]:
    """`aten.leaky_relu(Tensor self, Scalar negative_slope=0.01)` -- `vits`.

    The plausible wrong implementations:

      * **promoting an integral input like `relu` does** -- `relu` has an
        integral CPU kernel upstream and `leaky_relu` does not. `int64`,
        `uint8` and `bool` all raise `"leaky_relu_cpu" not implemented`, and
        each is cased.
      * **`max(x, slope * x)`** -- agrees with `x < 0 ? slope*x : x` for every
        slope in `[0, 1]`, which is every slope anyone writes. It differs at a
        **negative** slope: `leaky_relu(-1, -0.5)` is `0.5` upstream and `-1`
        from the max spelling. `negative_slope` is a `Scalar` with no sign
        constraint and upstream computes it, so that case is here.
      * **`x <= 0` instead of `x < 0`** -- differs only in the sign of the
        zero, which `==` cannot see. `_signed_zero_check` can.
      * **a default slope of 0 or 1** -- `F.leaky_relu(-1.0)` is `-0.01`.
    """
    op = "aten.leaky_relu.default"
    cases: list[Case] = []
    for dtype_name in ["float64", "float32", "float16", "bfloat16"]:
        for slope in (0.01, 0.1, 0.0, 1.0, -0.5, 2.0):
            a_t, a_c = pair_from_flat(
                torch_module, c_module, [-2.0, -1.0, 0.0, 1.0, 2.0], (5,), dtype_name)
            cases.append(
                Case(
                    name=f"leaky_relu(dtype={dtype_name}, slope={slope})",
                    op=op,
                    run_torch=lambda a_t=a_t, slope=slope: torch_call(a_t, slope),
                    run_c=lambda a_c=a_c, slope=slope: c_module._aten_dispatch(op, a_c, slope),
                    note="a negative slope is where max(x, slope*x) diverges",
                )
            )
        # The default slope, taken from the schema rather than passed.
        d_t, d_c = pair_from_flat(
            torch_module, c_module, [-1.0, 1.0], (2,), dtype_name)
        cases.append(
            Case(
                name=f"leaky_relu(dtype={dtype_name}) [default slope 0.01]",
                op=op,
                run_torch=lambda d_t=d_t: torch_call(d_t),
                run_c=lambda d_c=d_c: c_module._aten_dispatch(op, d_c),
                note="measured: leaky_relu(-1.0) is -0.01",
            )
        )
        s_t, s_c = pair_from_flat(
            torch_module, c_module,
            [float("nan"), float("inf"), float("-inf"), 0.0], (4,), dtype_name)
        cases.append(
            Case(
                name=f"leaky_relu(dtype={dtype_name}) [nan/+-inf]",
                op=op,
                run_torch=lambda s_t=s_t: torch_call(s_t, 0.1),
                run_c=lambda s_c=s_c: c_module._aten_dispatch(op, s_c, 0.1),
                note="-inf * 0.1 is -inf, not 0",
            )
        )
        # `-0.0` must stay `-0.0`, which needs the sign bit.
        z_t, z_c = pair_from_flat(
            torch_module, c_module, [-0.0, 0.0, -1.0, 1.0], (2, 2), dtype_name)
        cases.append(
            Case(
                name=f"leaky_relu(dtype={dtype_name}) [-0.0 keeps its sign]",
                op=op,
                run_torch=lambda z_t=z_t: torch_call(z_t, 0.5),
                run_c=lambda z_c=z_c: c_module._aten_dispatch(op, z_c, 0.5),
                value_check=_signed_zero_check,
                note="x < 0, not x <= 0 -- and 0.5 is exact so the comparator can be exact",
            )
        )
    for dtype_name in ("int64", "uint8", "bool"):
        flat = [1, 0] if dtype_name == "bool" else [-2, -1, 0, 1]
        if dtype_name == "uint8":
            flat = [0, 1, 2, 3]
        a_t, a_c = pair_from_flat(
            torch_module, c_module, flat, (len(flat),), dtype_name)
        cases.append(
            Case(
                name=f"leaky_relu(dtype={dtype_name}) [refused -- relu computes the same input]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, 0.1),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, 0.1),
                expect="both_error",
                note='"leaky_relu_cpu" not implemented for this dtype',
            )
        )
    # The spelling `F.leaky_relu` binds to. There is no `torch.leaky_relu` and
    # no `Tensor.leaky_relu` upstream, so `_C._nn` is the only door.
    for slope in (0.01, 0.1):
        pair = pair_from_flat(
            torch_module, c_module, [-2.0, -1.0, 0.0, 2.0], (2, 2), "float32")
        cases.append(
            _member_case(
                torch_module, c_module, op,
                f"spelling _nn.leaky_relu(x, {slope})", "float32", [pair],
                lambda m, a, slope=slope: (
                    m._nn if hasattr(m, "_nn") else m._C._nn).leaky_relu(a, slope),
                note="F.leaky_relu IS this binding; there is no torch.leaky_relu",
            )
        )
    return cases


def sign_cases(torch_module, c_module, torch_call) -> list[Case]:
    """`aten.sign(Tensor self)` -- `sew_d`'s wall after `erf`.

    `modeling_sew_d.py:160` takes `torch.sign(relative_pos)` on the
    disentangled-attention bucket table, on a `(19, 19)` int tensor.

    The plausible wrong implementations:

      * **`x > 0 ? 1 : -1`** -- a two-way sign. Fails on `0`, which must be
        `0`, and on NaN, which must also be `0`.
      * **promoting like `erf`** -- `sign` keeps the input dtype on every dtype
        *including* `bool`, where `erf` (landed in the same section) promotes
        every integral input to `float32`. Both rules were measured; neither
        follows from the other.
      * **`copysign(1, x)`** -- gives `1` for `+0.0` and `-1` for `-0.0`, where
        upstream gives `0` for both.
      * **returning `-0.0` for `-0.0`** -- upstream's `sign(-0.0)` is
        `+0.0`, checked on the sign bit and not on the value, since
        `-0.0 == 0.0`.
    """
    op = "aten.sign.default"
    cases: list[Case] = []
    for dtype_name in ["float64", "float32", "float16", "bfloat16"]:
        for flat, shape, note in (
            ([-2.5, -1.0, 0.0, 1.0, 2.5], (5,), "assorted, with a zero in the middle"),
            ([float("nan")], (1,), "NaN is 0.0, not NaN and not 1"),
            ([float("inf"), float("-inf")], (2,), "the infinities are ordinary"),
            ([1.0], (), "0-d"),
            ([], (0,), "empty"),
            ([1e-30, -1e-30], (2,), "tiny magnitudes still carry a sign"),
        ):
            cases.append(
                _unary_case(torch_module, c_module, op, torch_call, dtype_name,
                            flat, shape, note))
        # `sign(-0.0)` is `+0.0`. `-0.0 == 0.0` in Python, so this needs the
        # sign bit; and `sign` is exact on both sides, so the exact comparator
        # applies to every element here.
        z_t, z_c = pair_from_flat(
            torch_module, c_module, [-0.0, 0.0, -3.0, 3.0], (2, 2), dtype_name)
        cases.append(
            Case(
                name=f"sign(dtype={dtype_name}) [-0.0 gives +0.0, not -0.0]",
                op=op,
                run_torch=lambda z_t=z_t: torch_call(z_t),
                run_c=lambda z_c=z_c: c_module._aten_dispatch(op, z_c),
                value_check=_signed_zero_check,
                note="measured with copysign: both zeros come out POSITIVE",
            )
        )
    # The dtype is the input's, on every integral dtype and on bool -- which
    # is the half that separates this from `erf` beside it.
    for dtype_name, flat in (("int64", [-3, -1, 0, 1, 3]),
                             ("int32", [-3, -1, 0, 1, 3]),
                             ("uint8", [0, 1, 200]),
                             ("bool", [True, False])):
        cases.append(
            _unary_case(
                torch_module, c_module, op, torch_call, dtype_name,
                flat, (len(flat),),
                "the input dtype is kept -- bool in, bool out; erf promotes the same input",
            )
        )
    for spelling, call in (("torch.sign(x)", lambda m, a: _free(m, "sign")(a)),
                           ("x.sign()", lambda m, a: a.sign())):
        pair = pair_from_flat(
            torch_module, c_module, [-3, 0, 1, 3], (2, 2), "int64")
        cases.append(
            _member_case(
                torch_module, c_module, op, f"spelling {spelling}", "int64",
                [pair], call, note="sew_d spells the free function",
            )
        )
    return cases


def softplus_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.softplus.default"
    cases: list[Case] = []
    scenarios = [
        ([-5.0, -1.0, 0.0, 1.0, 5.0], (5,), "assorted, well inside the default threshold"),
        ([-1000.0, 1000.0], (2,), "far outside the default threshold -- 0.0 and exactly x"),
        ([0.0], (), "0-d"),
    ]
    for dtype_name in ["float64", "float32", "float16", "bfloat16"]:
        for flat, shape, note in scenarios:
            cases.append(_unary_case(torch_module, c_module, op, torch_call, dtype_name, flat, shape, note))

    # beta/threshold overrides -- mamba always calls with the defaults, but
    # the schema accepts both and the kernel's numerically-stable formula
    # has to answer them correctly too, not just the default pair.
    for beta, threshold, note in [
        (2.0, 20.0, "beta scales the input before the formula"),
        (1.0, 5.0, "a lower threshold moves the linear cutoff earlier"),
    ]:
        cases.append(
            _unary_case(
                torch_module, c_module, op, torch_call, "float32",
                [-5.0, -1.0, 0.0, 1.0, 5.0, 10.0], (6,), note,
                kwargs={"beta": beta, "threshold": threshold},
            )
        )

    # Refused, not promoted -- unlike exp/tanh, measured `softplus_cpu`
    # raises `NotImplementedError` naming the dtype rather than widening an
    # integral input to the default float.
    int_t, int_c = pair_from_flat(torch_module, c_module, [1, 2, 3], (3,), "int64")
    cases.append(
        Case(
            name="softplus(dtype=int64) [refused, NOT promoted -- unlike exp/tanh]",
            op=op,
            run_torch=lambda: torch_call(int_t),
            run_c=lambda: c_module._aten_dispatch(op, int_c),
            expect="both_error",
            note="torch: NotImplementedError('\"softplus_cpu\" not implemented for \\'Long\\'')",
        )
    )
    return cases


def convolution_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.convolution.default"
    cases: list[Case] = []

    def make(dtype_name, in_flat, in_shape, w_flat, w_shape, bias_flat, stride, padding, dilation, groups, note):
        x_t, x_c = pair_from_flat(torch_module, c_module, in_flat, in_shape, dtype_name)
        w_t, w_c = pair_from_flat(torch_module, c_module, w_flat, w_shape, dtype_name)
        if bias_flat is None:
            b_t, b_c = None, None
        else:
            b_t, b_c = pair_from_flat(torch_module, c_module, bias_flat, (w_shape[0],), dtype_name)
        return Case(
            name=f"convolution(dtype={dtype_name}, in={in_shape}, w={w_shape}, groups={groups}) [{note}]",
            op=op,
            run_torch=lambda: torch_call(
                x_t, w_t, b_t, list(stride), list(padding), list(dilation), False, [0], groups
            ),
            run_c=lambda: c_module._aten_dispatch(
                op, x_c, w_c, b_c, list(stride), list(padding), list(dilation), False, [0], groups
            ),
            note=note,
        )

    for dtype_name in ["float64", "float32"]:
        # mamba's exact shape: depthwise causal 1-D conv -- groups ==
        # in_channels == out_channels, padding == kernel_size - 1 (both
        # sides; the model slices `[..., :seq_len]` afterwards to keep it
        # causal, which is the caller's job, not this kernel's).
        cases.append(
            make(
                dtype_name,
                [1.0, 2.0, 3.0, 4.0, 5.0, -1.0, 0.5, 2.0, -2.0, 1.0, 0.0, 1.0, -1.0, 2.0, 3.0],
                (1, 3, 5),
                [1.0, -1.0, 0.5, 0.0, 0.5, 0.5, 0.5, 0.5, -1.0, 1.0, 0.0, 2.0],
                (3, 1, 4),
                [0.1, -0.2, 0.3],
                (1,), (3,), (1,), 3,
                "depthwise causal 1-D conv, mamba's exact shape (padding=kernel-1, groups=channels)",
            )
        )
        # groups=1 (ordinary, non-depthwise conv), no bias -- broader
        # coverage of `conv1d`'s groups argument than mamba alone exercises.
        cases.append(
            make(
                dtype_name,
                [1.0, 2.0, 3.0, 4.0, 5.0, 6.0],
                (1, 2, 3),
                [1.0, 0.0, -1.0, 1.0, 0.5, -0.5, 1.0, 1.0, 1.0, 1.0, -1.0, -1.0],
                (2, 2, 3),
                None,
                (1,), (1,), (1,), 1,
                "groups=1, no bias",
            )
        )

    x_t, x_c = pair_from_flat(torch_module, c_module, list(range(1, 16)), (1, 3, 5), "float32")
    w_t, w_c = pair_from_flat(torch_module, c_module, list(range(1, 13)), (3, 1, 4), "float32")

    # transposed=True, 1-D, **grouped**. This was `c_error` until
    # docs/KERNELS26.md §24 wired the 1-D transposed path for `vits`, and the
    # case flipped on its own -- "gap appears CLOSED: both sides now succeed,
    # promote this case to expect=match and diff real values", which is what
    # `c_error` exists to say. Promoted, and now diffing values.
    #
    # `groups=3` is not incidental: 1-D transposed keeps `groups` (candle's
    # `conv_transpose1d` takes one) where 2-D cannot (its
    # `ParamsConvTranspose2D` has no field for one), so this case is the one
    # that separates the two ranks rather than another copy of the ungrouped
    # geometry below.
    cases.append(
        Case(
            name="convolution(transposed=True, 1-D, groups=3)",
            op=op,
            run_torch=lambda: torch_call(x_t, w_t, None, [1], [3], [1], True, [0], 3),
            run_c=lambda: c_module._aten_dispatch(op, x_c, w_c, None, [1], [3], [1], True, [0], 3),
            note="1-D transposed convolution, grouped -- the rank 2-D cannot do",
        )
    )
    # A non-zero output_padding: also computes on real torch (measured),
    # also refused here for the same reason.
    cases.append(
        Case(
            name="convolution(output_padding=[1]) [c_error -- torch computes, shim refuses]",
            op=op,
            run_torch=lambda: torch_call(x_t, w_t, None, [1], [3], [1], False, [1], 3),
            run_c=lambda: c_module._aten_dispatch(op, x_c, w_c, None, [1], [3], [1], False, [1], 3),
            expect="c_error",
            note="a non-zero output_padding is not implemented in torch._C shim",
        )
    )
    # A rank-2 input: both sides refuse (measured on real torch: "Expected
    # 3-dimensional input for 3-dimensional weight").
    x2d_t, x2d_c = pair_from_flat(torch_module, c_module, [1.0, 2.0, 3.0, 4.0, 5.0, 6.0], (2, 3), "float32")
    cases.append(
        Case(
            name="convolution(rank-2 input) [both_error -- a rank-2 input has no batch axis]",
            op=op,
            run_torch=lambda: torch_call(x2d_t, w_t, None, [1], [3], [1], False, [0], 3),
            run_c=lambda: c_module._aten_dispatch(op, x2d_c, w_c, None, [1], [3], [1], False, [0], 3),
            expect="both_error",
            note="torch: 'Expected 3-dimensional input for 3-dimensional weight [3, 1, 4], "
                 "but got 2-dimensional input of size [2, 3] instead'",
        )
    )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1): every
    # argument by keyword at once -- `input`/`weight`, not `self`/`other`, are
    # this schema's own names for the two tensor arguments, and this op alone
    # accounts for six of the interned-name gap (groups/dilation/padding/
    # output_padding/stride/transposed).
    kw_x_t, kw_x_c = pair_from_flat(
        torch_module, c_module,
        [1.0, 2.0, 3.0, 4.0, 5.0, -1.0, 0.5, 2.0, -2.0, 1.0, 0.0, 1.0, -1.0, 2.0, 3.0],
        (1, 3, 5), "float32",
    )
    kw_w_t, kw_w_c = pair_from_flat(
        torch_module, c_module,
        [1.0, -1.0, 0.5, 0.0, 0.5, 0.5, 0.5, 0.5, -1.0, 1.0, 0.0, 2.0],
        (3, 1, 4), "float32",
    )
    # --- 2-D convolution (4-D input), docs/KERNELS26.md §7 -----------------
    #
    # `Dinov2`'s patch embedding is the caller ARCH26.md §3.2 stopped on, and
    # its shape is the first row: a square kernel with a matching stride and no
    # padding. The rest widen it in the ways a wrapper over a scalar-argument
    # kernel could get wrong -- padding, dilation, groups, and a NON-square
    # input, which is the one that catches an implementation that swapped the
    # height and width axes (a square input cannot).
    def make2d(dtype_name, in_shape, w_shape, with_bias, stride, padding, dilation,
               groups, note, expect="match"):
        n_in = 1
        for d in in_shape:
            n_in *= d
        n_w = 1
        for d in w_shape:
            n_w *= d
        in_flat = [((i * 37 % 23) - 11) * 0.25 for i in range(n_in)]
        w_flat = [((i * 17 % 13) - 6) * 0.5 for i in range(n_w)]
        x_t, x_c = pair_from_flat(torch_module, c_module, in_flat, in_shape, dtype_name)
        w_t, w_c = pair_from_flat(torch_module, c_module, w_flat, w_shape, dtype_name)
        if with_bias:
            b_flat = [((i % 5) - 2) * 0.1 for i in range(w_shape[0])]
            b_t, b_c = pair_from_flat(torch_module, c_module, b_flat, (w_shape[0],), dtype_name)
        else:
            b_t, b_c = None, None
        return Case(
            name=f"convolution 2-D(dtype={dtype_name}, in={in_shape}, w={w_shape}, "
                 f"stride={stride}, pad={padding}, dil={dilation}, groups={groups}) [{note}]",
            op=op,
            run_torch=lambda: torch_call(
                x_t, w_t, b_t, list(stride), list(padding), list(dilation), False, [0, 0], groups
            ),
            run_c=lambda: c_module._aten_dispatch(
                op, x_c, w_c, b_c, list(stride), list(padding), list(dilation), False, [0, 0], groups
            ),
            expect=expect,
            note=note,
        )

    for dtype_name in ["float64", "float32"]:
        for in_shape, w_shape, with_bias, stride, padding, dilation, groups, note in [
            # Dinov2's patch embedding, scaled down: (batch, 3, 8, 8) through a
            # 4x4 kernel with stride 4.
            ((2, 3, 8, 8), (4, 3, 4, 4), True, (4, 4), (0, 0), (1, 1), 1,
             "Dinov2 patch embedding shape (square kernel, matching stride, no padding)"),
            ((1, 2, 5, 5), (3, 2, 3, 3), True, (1, 1), (1, 1), (1, 1), 1,
             "the ordinary 3x3-with-padding case"),
            ((1, 2, 5, 5), (3, 2, 3, 3), False, (1, 1), (0, 0), (1, 1), 1, "no bias"),
            ((1, 2, 6, 6), (2, 2, 3, 3), True, (2, 2), (1, 1), (1, 1), 1, "stride 2"),
            ((1, 2, 7, 7), (2, 2, 3, 3), True, (1, 1), (2, 2), (2, 2), 1, "dilation 2"),
            ((1, 4, 5, 5), (4, 1, 3, 3), True, (1, 1), (1, 1), (1, 1), 4, "depthwise (groups=channels)"),
            ((1, 4, 5, 5), (4, 2, 3, 3), True, (1, 1), (1, 1), (1, 1), 2, "grouped, groups=2"),
            # NON-square: the row a square-only case set cannot fail on.
            ((1, 2, 4, 7), (3, 2, 3, 3), True, (1, 1), (1, 1), (1, 1), 1,
             "non-square input -- catches a swapped height/width axis"),
            ((1, 1, 6, 3), (2, 1, 3, 2), True, (1, 1), (0, 0), (1, 1), 1,
             "non-square input AND non-square kernel"),
            ((1, 2, 1, 1), (2, 2, 1, 1), True, (1, 1), (0, 0), (1, 1), 1, "1x1 kernel on a 1x1 input"),
        ]:
            cases.append(make2d(dtype_name, in_shape, w_shape, with_bias, stride,
                                padding, dilation, groups, note))

    # The documented gap: candle's `conv2d` takes one scalar per argument, so
    # an ASYMMETRIC stride/padding/dilation is refused. torch computes all
    # three. Carried as `c_error` so the harness watches the gap -- and so that
    # implementing it later flips these to failures rather than being silent.
    for stride, padding, dilation, which in [
        ((2, 1), (0, 0), (1, 1), "stride"),
        ((1, 1), (2, 0), (1, 1), "padding"),
        ((1, 1), (0, 0), (2, 1), "dilation"),
    ]:
        cases.append(
            make2d("float32", (1, 2, 7, 7), (2, 2, 3, 3), True, stride, padding,
                   dilation, 1, f"asymmetric {which} -- c_error, torch computes",
                   expect="c_error")
        )

    # **A single value broadcasts to both axes**, which is torch's own
    # `expand_param_if_needed` -- measured, and initially got wrong here: this
    # kernel first refused a 1-element list on a 4-D input, and that case
    # failed as `both_error` because torch computes `(1, 3, 3, 3)` for it. Kept
    # as a live case in both spellings.
    x4_t, x4_c = pair_from_flat(
        torch_module, c_module, [float(i) for i in range(1 * 2 * 5 * 5)], (1, 2, 5, 5), "float32")
    w4_t, w4_c = pair_from_flat(
        torch_module, c_module, [float(i % 7) for i in range(3 * 2 * 3 * 3)], (3, 2, 3, 3), "float32")
    for pad, note in (([0], "no padding"), ([2], "padding 2 on both axes")):
        cases.append(
            Case(
                name=f"convolution 2-D(4-D input, 1-element stride/padding/dilation) [{note}]",
                op=op,
                run_torch=lambda p=pad: torch_call(x4_t, w4_t, None, [1], p, [1], False, [0], 1),
                run_c=lambda p=pad: c_module._aten_dispatch(
                    op, x4_c, w4_c, None, [1], p, [1], False, [0], 1),
                note="a single value expands to every convolved axis",
            )
        )
    # ...and a length that is neither 1 nor the convolution's rank raises, on
    # both sides, with upstream's own wording.
    cases.append(
        Case(
            name="convolution 2-D(4-D input, 3-element stride) [both_error]",
            op=op,
            run_torch=lambda: torch_call(x4_t, w4_t, None, [1, 1, 1], [0], [1], False, [0], 1),
            run_c=lambda: c_module._aten_dispatch(
                op, x4_c, w4_c, None, [1, 1, 1], [0], [1], False, [0], 1),
            expect="both_error",
            note="torch: 'expected stride to be a single integer value or a list of 2 values'",
        )
    )
    x3b_t, x3b_c = pair_from_flat(
        torch_module, c_module, [float(i) for i in range(30)], (1, 2, 15), "float32")
    w3b_t, w3b_c = pair_from_flat(
        torch_module, c_module, [float(i) for i in range(12)], (2, 2, 3), "float32")
    cases.append(
        Case(
            name="convolution 1-D(3-D input, 2-element stride) [both_error]",
            op=op,
            run_torch=lambda: torch_call(x3b_t, w3b_t, None, [1, 1], [0], [1], False, [0], 1),
            run_c=lambda: c_module._aten_dispatch(
                op, x3b_c, w3b_c, None, [1, 1], [0], [1], False, [0], 1),
            expect="both_error",
            note="a 2-element stride on a 1-D convolution is refused upstream too -- "
                 "this is not a shim restriction",
        )
    )

    cases.append(
        Case(
            name="convolution(every argument by keyword)",
            op=op,
            run_torch=lambda: torch_call(
                input=kw_x_t, weight=kw_w_t, bias=None, stride=[1], padding=[3],
                dilation=[1], transposed=False, output_padding=[0], groups=3,
            ),
            run_c=lambda: c_module._aten_dispatch(
                op, input=kw_x_c, weight=kw_w_c, bias=None, stride=[1], padding=[3],
                dilation=[1], transposed=False, output_padding=[0], groups=3,
            ),
        )
    )

    # --- transposed 2-D convolution, docs/KERNELS26.md §10 -------------------
    #
    # **The weight layout is `(in_channels, out_channels/groups, kH, kW)` --
    # the opposite of the forward convolution's `(out, in/groups, kH, kW)` --
    # and getting it backwards produces a plausible tensor rather than an
    # error.** That is the whole reason this block exists and why it is built
    # the way it is.
    #
    # `zoedepth`'s own call cannot show it. `ZoeDepthUpsample` is
    # `nn.ConvTranspose2d(channels, channels, kernel_size=factor,
    # stride=factor, padding=0)`: equal in/out channels and a square kernel, so
    # swapping the first two weight axes gives a tensor of exactly the same
    # shape. Measured on a `(1,2,3,3)` input with a `(2,2,3,3)` weight:
    #
    #     correct                     sum 61317   [162, 351, 569, 413, 224, ...]
    #     first two axes swapped      sum 54756   [ 81, 180, 299, 224, 125, ...]
    #     kernel flipped spatially    sum 61317   [234, 493, 775, 535, 276, ...]
    #
    # The spatial flip **keeps the sum identical** and changes every element, so
    # a checksum-shaped test passes it. Both wrong layouts are carried below as
    # live cases, compared element by element.
    #
    # The layout itself was established on a case that *can* show it -- unequal
    # channels and a non-square kernel -- three independent ways: the accepted
    # shape (`x(2,3,5,7) @ w(3,5,2,4) -> (2,5,6,10)`, so `out_channels` is
    # `w.shape[1]`), `nn.ConvTranspose2d(3, 5, (2,4)).weight.shape == [3,5,2,4]`,
    # and a from-scratch scatter-add implementation of the definition.

    def tmake(dtype_name, in_flat, in_shape, w_flat, w_shape, bias_flat,
              stride, padding, dilation, output_padding, groups, note,
              expect="match"):
        x_t, x_c = pair_from_flat(torch_module, c_module, in_flat, in_shape, dtype_name)
        w_t, w_c = pair_from_flat(torch_module, c_module, w_flat, w_shape, dtype_name)
        if bias_flat is None:
            b_t, b_c = None, None
        else:
            # (out_channels,) -- and for a TRANSPOSED weight that is
            # `w_shape[1] * groups`, not `w_shape[0]`. Writing `w_shape[0]`
            # here (the forward convolution's rule, and what the `make` helper
            # above does) is the same layout mistake in the bias.
            b_t, b_c = pair_from_flat(
                torch_module, c_module, bias_flat, (w_shape[1] * groups,), dtype_name
            )
        return Case(
            name=f"convolution transposed({dtype_name}, in={in_shape}, w={w_shape}, "
                 f"stride={stride}, pad={padding}, dil={dilation}, "
                 f"outpad={output_padding}, groups={groups}) [{note}]",
            op=op,
            run_torch=lambda: torch_call(
                x_t, w_t, b_t, list(stride), list(padding), list(dilation),
                True, list(output_padding), groups,
            ),
            run_c=lambda: c_module._aten_dispatch(
                op, x_c, w_c, b_c, list(stride), list(padding), list(dilation),
                True, list(output_padding), groups,
            ),
            expect=expect,
            note=note,
        )

    # 1. The case that PINS the layout: in=3, out=5, kernel 2x4. Every one of
    #    those four numbers is different, so a weight read in any other order
    #    is a different shape.
    x_asym = [float(v) * 0.37 - 5.0 for v in range(2 * 3 * 5 * 7)]
    w_asym = [float(v) * 0.11 - 1.0 for v in range(3 * 5 * 2 * 4)]
    for dtype_name in ("float64", "float32"):
        cases.append(
            tmake(
                dtype_name, x_asym, (2, 3, 5, 7), w_asym, (3, 5, 2, 4),
                [0.1, -0.2, 0.3, -0.4, 0.5], (1,), (0,), (1,), (0,), 1,
                "in=3 out=5 kernel 2x4 -- no two axes interchangeable",
            )
        )
    # 2. The DANGEROUS case: equal channels, square kernel. Same shape under
    #    both wrong layouts, so only the values separate them.
    x_sq = [float(v) for v in range(1 * 2 * 3 * 3)]
    w_sq = [float(v) for v in range(2 * 2 * 3 * 3)]
    cases.append(
        tmake(
            "float64", x_sq, (1, 2, 3, 3), w_sq, (2, 2, 3, 3), None,
            (1,), (0,), (1,), (0,), 1,
            "equal channels, square kernel -- a swapped or flipped weight has "
            "the SAME shape here, and a flipped one has the same sum too",
        )
    )
    # 2b. The same operands with the weight actually transposed on the way in,
    #     so the harness compares the two arrangements rather than trusting a
    #     comment that says they differ. Upstream and the shim must BOTH answer
    #     the swapped-weight result for a swapped weight -- if this case ever
    #     matches case 2's values, the kernel is ignoring the axis order.
    w_sq_swapped = []
    for i in range(2):
        for o in range(2):
            for a in range(3):
                for b in range(3):
                    # w_sq is (2,2,3,3) in C order; take [o][i][a][b]
                    w_sq_swapped.append(w_sq[((o * 2 + i) * 3 + a) * 3 + b])
    cases.append(
        tmake(
            "float64", x_sq, (1, 2, 3, 3), w_sq_swapped, (2, 2, 3, 3), None,
            (1,), (0,), (1,), (0,), 1,
            "the same weight with its first two axes exchanged -- must give a "
            "DIFFERENT answer from the case above, on both sides",
        )
    )
    # 3. zoedepth's own shape: ConvTranspose2d(c, c, kernel_size=f, stride=f).
    for factor in (2, 3):
        c_ch = 2
        xf = [float(v) * 0.25 - 1.0 for v in range(1 * c_ch * 4 * 4)]
        wf = [float(v) * 0.1 - 0.5 for v in range(c_ch * c_ch * factor * factor)]
        cases.append(
            tmake(
                "float32", xf, (1, c_ch, 4, 4), wf, (c_ch, c_ch, factor, factor),
                [0.25, -0.5], (factor,), (0,), (1,), (0,), 1,
                f"zoedepth's ZoeDepthUpsample, factor={factor}",
            )
        )
    # 4. Each geometric argument varied ALONE and to a distinct value, so that
    #    passing them to candle in the wrong order -- its signature is
    #    `(kernel, padding, output_padding, stride, dilation)`, which is not
    #    `conv2d`'s `(kernel, padding, stride, dilation, groups)` -- changes the
    #    output shape and fails here.
    x4 = [float(v) * 0.19 - 3.0 for v in range(1 * 2 * 4 * 4)]
    w4 = [float(v) * 0.07 - 0.9 for v in range(2 * 3 * 3 * 3)]
    for stride, padding, dilation, outpad, note in [
        ((2,), (0,), (1,), (0,), "stride alone"),
        ((1,), (2,), (1,), (0,), "padding alone"),
        ((1,), (0,), (3,), (0,), "dilation alone"),
        ((3,), (0,), (1,), (2,), "output_padding alone (needs stride > it)"),
        ((3,), (1,), (2,), (2,), "all four at once, all different"),
        ((1,), (0,), (2,), (1,), "output_padding bounded by DILATION, not stride"),
    ]:
        cases.append(
            tmake(
                "float64", x4, (1, 2, 4, 4), w4, (2, 3, 3, 3),
                [0.1, -0.1, 0.2], stride, padding, dilation, outpad, 1, note,
            )
        )
    # 5. Non-square kernel with the geometry varied too -- the height/width axes
    #    must not be interchangeable anywhere in the wrapper.
    x5 = [float(v) * 0.13 - 2.0 for v in range(1 * 2 * 3 * 5)]
    w5 = [float(v) * 0.09 - 0.4 for v in range(2 * 3 * 2 * 4)]
    cases.append(
        tmake(
            "float64", x5, (1, 2, 3, 5), w5, (2, 3, 2, 4), None,
            (2,), (1,), (1,), (1,), 1,
            "non-square input AND non-square kernel, strided and padded",
        )
    )
    # 6. Refusals. Each computes upstream and is refused here by name.
    cases.append(
        tmake(
            "float32", [float(v) for v in range(1 * 4 * 4 * 4)], (1, 4, 4, 4),
            [float(v) for v in range(4 * 2 * 3 * 3)], (4, 2, 3, 3), None,
            (1,), (0,), (1,), (0,), 2,
            "grouped transposed convolution -- candle's conv_transpose2d takes "
            "no groups argument",
            expect="c_error",
        )
    )
    for stride, padding, dilation, outpad, note in [
        ((2, 1), (0, 0), (1, 1), (0, 0), "asymmetric stride"),
        ((1, 1), (1, 0), (1, 1), (0, 0), "asymmetric padding"),
        ((1, 1), (0, 0), (2, 1), (0, 0), "asymmetric dilation"),
        ((2, 2), (0, 0), (1, 1), (1, 0), "asymmetric output_padding"),
    ]:
        cases.append(
            tmake(
                "float32", x4, (1, 2, 4, 4), w4, (2, 3, 3, 3), None,
                stride, padding, dilation, outpad, 1,
                note + " -- candle's conv_transpose2d takes one value per "
                "argument, not one per axis",
                expect="c_error",
            )
        )
    # 1-D transposed (3-D input), ungrouped. Also `c_error` until §24 --
    # docs/KERNELS26.md §10.3 refused it for "no measured caller", and `vits`
    # became one.
    cases.append(
        Case(
            name="convolution transposed(3-D input, groups=1)",
            op=op,
            run_torch=lambda: torch_call(x_t, w_t, None, [1], [0], [1], True, [0], 1),
            run_c=lambda: c_module._aten_dispatch(
                op, x_c, w_c, None, [1], [0], [1], True, [0], 1
            ),
            note="the plain 1-D transposed convolution",
        )
    )
    # vits' own geometry: a stride equal to half the kernel and a matching
    # padding, which is what `nn.ConvTranspose1d(c, c//2, k, stride=r,
    # padding=(k-r)//2)` produces. Unequal in/out channels, so a transposed
    # weight layout is a shape error rather than a plausible tensor -- the
    # separation §10.1 had to build by hand for the 2-D case.
    vx_t, vx_c = pair_from_flat(
        torch_module, c_module, [float(i % 7) - 3.0 for i in range(2 * 4 * 6)],
        (2, 4, 6), "float32")
    vw_t, vw_c = pair_from_flat(
        torch_module, c_module, [float((i * 3) % 11) - 5.0 for i in range(4 * 2 * 8)],
        (4, 2, 8), "float32")
    vb_t, vb_c = pair_from_flat(
        torch_module, c_module, [0.5, -0.25], (2,), "float32")
    for bias_t, bias_c, label in ((None, None, "no bias"), (vb_t, vb_c, "with bias")):
        cases.append(
            Case(
                name=f"convolution transposed(1-D, 4->2 channels, k=8, stride=4, pad=2) [{label}]",
                op=op,
                run_torch=lambda b=bias_t: torch_call(
                    vx_t, vw_t, b, [4], [2], [1], True, [0], 1),
                run_c=lambda b=bias_c: c_module._aten_dispatch(
                    op, vx_c, vw_c, b, [4], [2], [1], True, [0], 1),
                note="vits' HiFi-GAN upsample geometry; unequal channels, so a "
                     "transposed weight layout is a shape error not a plausible tensor",
            )
        )
    # ...and through the spelling `F.conv_transpose1d` binds to, which is
    # `torch.conv_transpose1d` itself -- the door golden's dispatch key cannot
    # see. `groups` before `dilation`, positionally, so a signature copied
    # from `conv1d` swaps them.
    for label, call in (
        ("keyword", lambda m, x, w, b: _free(m, "conv_transpose1d")(
            x, w, b, stride=4, padding=2, output_padding=0, groups=1, dilation=1)),
        ("positional (groups BEFORE dilation)", lambda m, x, w, b: _free(
            m, "conv_transpose1d")(x, w, b, 4, 2, 0, 1, 1)),
    ):
        px = pair_from_flat(
            torch_module, c_module, [float(i % 7) - 3.0 for i in range(2 * 4 * 6)],
            (2, 4, 6), "float32")
        pw = pair_from_flat(
            torch_module, c_module, [float((i * 3) % 11) - 5.0 for i in range(4 * 2 * 8)],
            (4, 2, 8), "float32")
        pb = pair_from_flat(torch_module, c_module, [0.5, -0.25], (2,), "float32")
        cases.append(
            _member_case(
                torch_module, c_module, op,
                f"spelling torch.conv_transpose1d, {label}", "float32",
                [px, pw, pb], call,
                note="F.conv_transpose1d IS torch.conv_transpose1d, asserted in test_shim.py",
            )
        )
    # 7. output_padding >= max(stride, dilation) raises on BOTH sides, with
    #    upstream's exact wording. The bound is max(stride, dilation) and not
    #    stride -- measured: outpad=1 is accepted with stride=1, dilation=2 and
    #    refused with stride=1, dilation=1.
    for stride, dilation, outpad, note in [
        ((1,), (1,), (1,), "outpad 1 with stride 1, dilation 1"),
        ((2,), (1,), (2,), "outpad 2 with stride 2"),
        ((1,), (2,), (2,), "outpad 2 with dilation 2"),
    ]:
        cases.append(
            tmake(
                "float32", x4, (1, 2, 4, 4), w4, (2, 3, 3, 3), None,
                stride, (0,), dilation, outpad, 1,
                note + " -- 'output padding must be smaller than either stride "
                "or dilation'",
                expect="both_error",
            )
        )
    return cases


def zeros_like_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.zeros_like.default"
    cases: list[Case] = []
    for dtype_name in ["float64", "float32", "int64", "uint8"]:
        a_t, a_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4, 5, 6], (2, 3), dtype_name)
        cases.append(
            Case(
                name=f"zeros_like(dtype={dtype_name}, shape=(2,3)) [dtype/shape inherited from self]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c),
                note="mamba seeds the SSM's running state this way",
            )
        )
    for dtype_name in dt.DEFAULT_DTYPES:
        t_dt = dt.torch_dtype(torch_module, dtype_name)
        c_dt = dt.c_dtype(c_module, dtype_name)
        a_t, a_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (2, 2), "float32")
        cases.append(
            Case(
                name=f"zeros_like(self_dtype=float32, dtype_override={dtype_name})",
                op=op,
                run_torch=lambda a_t=a_t, t_dt=t_dt: torch_call(a_t, dtype=t_dt),
                run_c=lambda a_c=a_c, c_dt=c_dt: c_module._aten_dispatch(op, a_c, dtype=c_dt),
                note="explicit dtype override beats the self tensor's dtype",
            )
        )
    return cases


def ones_like_cases(torch_module, c_module, torch_call) -> list[Case]:
    """`aten.ones_like.default` -- the wall `vits` AND `sam3_video` both reached.

    The same function as `zeros_like`/`empty_like` with a different fill, but
    **the only one of the three whose values can actually be diffed**: `zeros`
    and `empty` share `_dtype_shape_only_check` because upstream's `empty` bytes
    are undefined, while `ones` is defined to be ones. So these cases run the
    default pipeline, and a fill that answered zeros -- which is what reusing
    the sibling branch by accident would do -- fails on the values rather than
    passing on the dtype.
    """
    op = "aten.ones_like.default"
    cases: list[Case] = []
    for dtype_name in ["float64", "float32", "float16", "bfloat16", "int64", "int32", "uint8", "bool"]:
        a_t, a_c = pair_from_flat(
            torch_module, c_module, [1, 2, 3, 4, 5, 6], (2, 3), dtype_name
        )
        cases.append(
            Case(
                name=f"ones_like(dtype={dtype_name}, shape=(2,3)) [dtype/shape from self]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c),
                note="values are DEFINED here, unlike zeros_like's sibling "
                "empty_like -- so this diffs them",
            )
        )
    # An explicit dtype override beats the reference tensor's dtype.
    for dtype_name in dt.DEFAULT_DTYPES:
        t_dt = dt.torch_dtype(torch_module, dtype_name)
        c_dt = dt.c_dtype(c_module, dtype_name)
        a_t, a_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (2, 2), "float32")
        cases.append(
            Case(
                name=f"ones_like(self_dtype=float32, dtype_override={dtype_name})",
                op=op,
                run_torch=lambda a_t=a_t, t_dt=t_dt: torch_call(a_t, dtype=t_dt),
                run_c=lambda a_c=a_c, c_dt=c_dt: c_module._aten_dispatch(op, a_c, dtype=c_dt),
                note="explicit dtype override beats the self tensor's dtype",
            )
        )
    # Shapes that a fill written against a flat buffer could get wrong.
    for shape in ((0,), (1,), (3, 1), (2, 3, 4)):
        n = 1
        for d in shape:
            n *= d
        a_t, a_c = pair_from_flat(
            torch_module, c_module, [1.0] * n, shape, "float32"
        )
        cases.append(
            Case(
                name=f"ones_like(float32, shape={shape})",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c),
                note="including the empty shape, where a fill has nothing to do",
            )
        )
    return cases


def empty_like_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.empty_like.default"
    cases: list[Case] = []
    for dtype_name in ["float64", "float32", "int64", "uint8"]:
        a_t, a_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4, 5, 6], (2, 3), dtype_name)
        cases.append(
            Case(
                name=f"empty_like(dtype={dtype_name}, shape=(2,3))",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c),
                value_check=_dtype_shape_only_check,
                note="uninitialized memory -- only dtype/shape are meaningful (mixtral's routing "
                     "immediately overwrites every element via index_put_ before reading it)",
            )
        )
    return cases


def ge_scalar_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.ge.Scalar"
    cases: list[Case] = []
    for dtype_name in _CMP_DTYPES:
        cases.append(
            _binary_scalar_case(
                torch_module, c_module, op, torch_call, dtype_name,
                [1, 2, 3, 4], (2, 2), 3,
                "x >= 3 -- mixtral's sentinel_mask = expert_ids_g >= num_experts",
            )
        )
    cases.append(
        Case(
            name="ge(float32, nan >= 1.0) [every comparison against NaN is false]",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [float("nan"), 1.0], (2,), "float32")[0], 1.0
            ),
            run_c=lambda: c_module._aten_dispatch(
                op, _pair(torch_module, c_module, [float("nan"), 1.0], (2,), "float32")[1], 1.0
            ),
            note="NaN is not >= anything, including itself",
        )
    )
    cases.extend(_ge_member_cases(torch_module, c_module))
    return cases


# --- aten.ge.Tensor ----------------------------------------------------------
#
# The last of the six comparisons to get its Tensor overload. `le.Tensor`,
# `lt.Tensor` and `gt.Tensor` all had a kernel and `ge` had only `.Scalar`, so
# `x >= tensor` resolved through `methods.json` (docs/GROUPED_MM.md §6.4 put
# both schema strings there) and then refused inside `_aten_dispatch`. The
# cases mirror `gt.Tensor`'s exactly, because the two are the same kernel
# under a different `Cmp` -- a divergence between them would be a real one.


def ge_tensor_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.ge.Tensor"
    cases: list[Case] = []
    for dtype_name in _CMP_DTYPES:
        for sc in _CMP_SCENARIOS:
            cases.append(
                _binary_tensor_case(
                    torch_module, c_module, op, torch_call, dtype_name,
                    sc["a_flat"], sc["a_shape"], sc["b_flat"], sc["b_shape"], sc["note"],
                )
            )
    cases.append(
        Case(
            name="ge(int64, x >= x is True) [equality boundary -- the half that separates ge from gt]",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [1, 2, 3], (3,), "int64")[0],
                _pair(torch_module, c_module, [1, 2, 3], (3,), "int64")[0],
            ),
            run_c=lambda: c_module._aten_dispatch(
                op,
                _pair(torch_module, c_module, [1, 2, 3], (3,), "int64")[1],
                _pair(torch_module, c_module, [1, 2, 3], (3,), "int64")[1],
            ),
            note="every element compared against itself -- non-strict >=, so all True. "
                 "gt.Tensor's matching case is all False, which is what pins Cmp::Ge to "
                 "this key rather than Cmp::Gt",
        )
    )
    cases.append(
        Case(
            name="ge(float32, nan >= nan and 3.0 >= nan) [every comparison against NaN is false]",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [float("nan"), 3.0, 2.0], (3,), "float32")[0],
                _pair(torch_module, c_module, [float("nan"), 2.0, float("nan")], (3,), "float32")[0],
            ),
            run_c=lambda: c_module._aten_dispatch(
                op,
                _pair(torch_module, c_module, [float("nan"), 3.0, 2.0], (3,), "float32")[1],
                _pair(torch_module, c_module, [float("nan"), 2.0, float("nan")], (3,), "float32")[1],
            ),
            note="NaN on either side (or both) makes that element False even though >= is "
                 "the reflexive comparison",
        )
    )
    cases.append(
        Case(
            name="ge(bool, [T,F,T] >= [F,F,T]) [bool compares as 0/1]",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [1, 0, 1], (3,), "bool")[0],
                _pair(torch_module, c_module, [0, 0, 1], (3,), "bool")[0],
            ),
            run_c=lambda: c_module._aten_dispatch(
                op,
                _pair(torch_module, c_module, [1, 0, 1], (3,), "bool")[1],
                _pair(torch_module, c_module, [0, 0, 1], (3,), "bool")[1],
            ),
            note="True >= False, False >= False and True >= True are all True (measured)",
        )
    )
    cases.append(
        Case(
            name="ge(int64, causal mask idiom) [arange(S)[:,None] >= arange(S)[None]]",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [0, 1, 2, 3], (1, 1, 4, 1), "int64")[0],
                _pair(torch_module, c_module, [0, 1, 2, 3], (1, 1, 1, 4), "int64")[0],
            ),
            run_c=lambda: c_module._aten_dispatch(
                op,
                _pair(torch_module, c_module, [0, 1, 2, 3], (1, 1, 4, 1), "int64")[1],
                _pair(torch_module, c_module, [0, 1, 2, 3], (1, 1, 1, 4), "int64")[1],
            ),
            note="the same lower-triangular mask le.Tensor's case builds, written the other "
                 "way round -- the broadcast that four architectures use",
        )
    )
    cases.extend(_ge_tensor_member_cases(torch_module, c_module))
    return cases


def floor_divide_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.floor_divide.default"
    cases: list[Case] = []

    # Tensor,Tensor -- mixed sign, re-measured against real torch: floors
    # toward -inf like Python's `//`, not toward zero like C's truncation.
    for dtype_name in ["int64", "int32"]:
        a_t, a_c = pair_from_flat(torch_module, c_module, [-7, -6, -1, 0, 1, 6, 7], (7,), dtype_name)
        b_t, b_c = pair_from_flat(torch_module, c_module, [2, 2, 2, 2, 2, 2, 2], (7,), dtype_name)
        cases.append(
            Case(
                name=f"floor_divide(dtype={dtype_name}, tensor/tensor, mixed-sign self / positive divisor)",
                op=op,
                run_torch=lambda a_t=a_t, b_t=b_t: torch_call(a_t, b_t),
                run_c=lambda a_c=a_c, b_c=b_c: c_module._aten_dispatch(op, a_c, b_c),
                note="[-7,-6,-1,0,1,6,7] // 2 == [-4,-3,-1,0,0,3,3], measured -- floors toward "
                     "-inf, does not truncate toward zero",
            )
        )
        c_t, c_c = pair_from_flat(torch_module, c_module, [-7, -6, -1, 0, 1, 6, 7], (7,), dtype_name)
        d_t, d_c = pair_from_flat(torch_module, c_module, [-2, -2, -2, -2, -2, -2, -2], (7,), dtype_name)
        cases.append(
            Case(
                name=f"floor_divide(dtype={dtype_name}, tensor/tensor, mixed-sign self / negative divisor)",
                op=op,
                run_torch=lambda c_t=c_t, d_t=d_t: torch_call(c_t, d_t),
                run_c=lambda c_c=c_c, d_c=d_c: c_module._aten_dispatch(op, c_c, d_c),
                note="[-7,-6,-1,0,1,6,7] // -2 == [3,3,0,0,-1,-3,-4], measured",
            )
        )

    # Tensor,Scalar -- mixtral's exact call shape (`perm // num_top_k`, a
    # bare Python int reaching the (Tensor, Tensor) overload's `other` slot
    # -- see the kernel's own doc comment).
    e_t, e_c = pair_from_flat(torch_module, c_module, [-7, -6, -1, 0, 1, 6, 7], (7,), "int64")
    cases.append(
        Case(
            name="floor_divide(dtype=int64, tensor // python-int scalar)",
            op=op,
            run_torch=lambda: torch_call(e_t, 2),
            run_c=lambda: c_module._aten_dispatch(op, e_c, 2),
            note="mixtral's exact call shape: perm // num_top_k",
        )
    )

    # Floating dtype: division by zero is not an error (IEEE inf/-inf/nan).
    f_t, f_c = pair_from_flat(torch_module, c_module, [1.0, -1.0, 0.0], (3,), "float32")
    g_t, g_c = pair_from_flat(torch_module, c_module, [0.0, 0.0, 0.0], (3,), "float32")
    cases.append(
        Case(
            name="floor_divide(dtype=float32, division by zero -- inf/-inf/nan, not an error)",
            op=op,
            run_torch=lambda: torch_call(f_t, g_t),
            run_c=lambda: c_module._aten_dispatch(op, f_c, g_c),
            note="measured: [1.,-1.,0.] // [0.,0.,0.] == [inf,-inf,nan]",
        )
    )

    # Integral dtype: division by zero raises, matching upstream's exact
    # message (measured: RuntimeError('ZeroDivisionError')).
    h_t, h_c = pair_from_flat(torch_module, c_module, [1, 0, -1], (3,), "int64")
    i_t, i_c = pair_from_flat(torch_module, c_module, [2, 0, -2], (3,), "int64")
    cases.append(
        Case(
            name="floor_divide(dtype=int64, division by zero) [raises]",
            op=op,
            run_torch=lambda: torch_call(h_t, i_t),
            run_c=lambda: c_module._aten_dispatch(op, h_c, i_c),
            expect="both_error",
            note="torch: RuntimeError('ZeroDivisionError'), same wording reproduced here",
        )
    )
    return cases


def floor_divide_scalar_cases(torch_module, c_module, torch_call) -> list[Case]:
    """`aten.floor_divide.Scalar` -- the key this shim's resolver picks for
    `torch.floor_divide(tensor, 2)` where upstream picks `.default`.

    The value is the same arithmetic and the cases are `floor_divide_cases`'
    scalar half repeated against *this* key, because that is the one Mixtral's
    routing actually reaches through the Python surface. Both keys are compared
    against upstream separately, so if the resolver is ever taught upstream's
    "numbers as tensors" rule, neither side of the change goes unchecked.
    """
    op = "aten.floor_divide.Scalar"
    cases: list[Case] = []

    for dtype_name in ["int64", "int32"]:
        a_t, a_c = pair_from_flat(torch_module, c_module, [-7, -6, -1, 0, 1, 6, 7], (7,), dtype_name)
        for divisor, note in [
            (2, "[-7,-6,-1,0,1,6,7] // 2 == [-4,-3,-1,0,0,3,3] -- floors toward -inf"),
            (-2, "[-7,-6,-1,0,1,6,7] // -2 == [3,3,0,0,-1,-3,-4] -- a negative divisor flips the correction"),
            (1, "the identity divisor, where a wrong floor correction still cannot show"),
        ]:
            cases.append(
                Case(
                    name=f"floor_divide.Scalar(dtype={dtype_name}, // {divisor})",
                    op=op,
                    run_torch=lambda a_t=a_t, d=divisor: torch_call(a_t, d),
                    run_c=lambda a_c=a_c, d=divisor: c_module._aten_dispatch(op, a_c, d),
                    note=note,
                )
            )
        cases.append(
            Case(
                name=f"floor_divide.Scalar(dtype={dtype_name}, // 0) [raises]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, 0),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, 0),
                expect="both_error",
                note="torch: RuntimeError('ZeroDivisionError') on an integral dtype",
            )
        )

    f_t, f_c = pair_from_flat(torch_module, c_module, [1.0, -1.0, 0.0, 7.5, -7.5], (5,), "float32")
    cases.append(
        Case(
            name="floor_divide.Scalar(dtype=float32, // 2.0)",
            op=op,
            run_torch=lambda: torch_call(f_t, 2.0),
            run_c=lambda: c_module._aten_dispatch(op, f_c, 2.0),
            note="7.5 // 2.0 == 3.0 and -7.5 // 2.0 == -4.0 -- the float path floors too",
        )
    )
    cases.append(
        Case(
            name="floor_divide.Scalar(dtype=float32, // 0.0) [inf/-inf/nan, not an error]",
            op=op,
            run_torch=lambda: torch_call(f_t, 0.0),
            run_c=lambda: c_module._aten_dispatch(op, f_c, 0.0),
            note="a floating zero divisor is IEEE, not a refusal -- unlike the integral one",
        )
    )

    # A tensor in the `Scalar other` slot is `.default`'s call. Upstream's own
    # binding refuses it for this key, and folding the two together here would
    # make the work queue unable to tell them apart.
    t_t, t_c = pair_from_flat(torch_module, c_module, [2, 2, 2, 2, 2, 2, 2], (7,), "int64")
    i_t, i_c = pair_from_flat(torch_module, c_module, [-7, -6, -1, 0, 1, 6, 7], (7,), "int64")
    cases.append(
        Case(
            name="floor_divide.Scalar(a tensor divisor is the other overload) [refused]",
            op=op,
            run_torch=lambda: torch_call(i_t, t_t),
            run_c=lambda: c_module._aten_dispatch(op, i_c, t_c),
            expect="both_error",
            note="aten::floor_divide.Scalar takes a Scalar; a Tensor there is aten.floor_divide.default",
        )
    )

    # The reduced-float scalar rule (docs/SCALAR.md §3.2), and with it the
    # `float64` gap that shares its cause: this builder's float coverage was
    # `// 2.0` and `// 0.0`, both of which are exactly representable *and* land
    # on an exact quotient, so `floor(a/b)` and upstream's fmod-based
    # `div_floor_floating` agreed on every one of them. `-3.0 // 0.3` is `-11`
    # upstream (the f64 quotient is -10.000000000000002) and was `-10` here.
    cases.extend(
        _scalar_rule_cases(
            torch_module, c_module, op,
            lambda t, s: torch_call(t, s),
            lambda c, s: c_module._aten_dispatch(op, c, s),
            rule="widen",
            why="div_floor_kernel's reduced-float branch reads "
                "original_scalar_value<opmath_t>(2); at float64 the same call "
                "exposes that this key floored the quotient instead of running "
                "upstream's div_floor_floating",
            dtypes=["float64", "float32", "float16", "bfloat16"],
            # `_div_mode_scalar_cases`' set, for its reason -- the shared
            # values separate almost nothing under a floor. See there.
            values=[7.0, 14.0, 40.0, 43.0, 48.0, 61.0, 100.0, -49.0],
            separating=(0.3, 0.7, 1.3, 0.1),
        )
    )
    return cases


def histc_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.histc.default"
    cases: list[Case] = []

    # mixtral's exact call shape: float32 input, bins=num_experts, min=0,
    # max=num_experts-1.
    a_t, a_c = pair_from_flat(torch_module, c_module, [0.0, 1.0, 2.0, 3.0, 3.0, -1.0, 4.0], (7,), "float32")
    cases.append(
        Case(
            name="histc(dtype=float32, bins=4, min=0, max=3) [out-of-range values dropped]",
            op=op,
            run_torch=lambda: torch_call(a_t, 4, 0, 3),
            run_c=lambda: c_module._aten_dispatch(op, a_c, 4, 0, 3),
            note="-1.0 and 4.0 fall outside [0,3] and are not counted, measured",
        )
    )

    for dtype_name in ["float64", "float32", "float16"]:
        b_t, b_c = pair_from_flat(torch_module, c_module, [1.0, 2.0, 3.0], (3,), dtype_name)
        cases.append(
            Case(
                name=f"histc(dtype={dtype_name}, bins=4, min=0, max=3)",
                op=op,
                run_torch=lambda b_t=b_t: torch_call(b_t, 4, 0, 3),
                run_c=lambda b_c=b_c: c_module._aten_dispatch(op, b_c, 4, 0, 3),
                note="output dtype follows the input's, not a fixed default",
            )
        )

    # min == max: falls back to the data's own [min, max] -- re-measured on
    # real torch with a *non-zero* equal bound too, not only min=max=0.
    c_t, c_c = pair_from_flat(torch_module, c_module, [1.0, 2.0, 3.0], (3,), "float32")
    cases.append(
        Case(
            name="histc(min==max==5, non-zero) [falls back to the data's own min/max]",
            op=op,
            run_torch=lambda: torch_call(c_t, 4, 5, 5),
            run_c=lambda: c_module._aten_dispatch(op, c_c, 4, 5, 5),
            note="measured: ignores the literal value 5 entirely, uses the data's range [1,3]",
        )
    )

    # Degenerate: the data itself is constant, so even the auto-detected
    # range collapses -- falls back a second time to [value-1, value+1].
    d_t, d_c = pair_from_flat(torch_module, c_module, [2.0, 2.0, 2.0], (3,), "float32")
    cases.append(
        Case(
            name="histc(constant data, min=max=0) [degenerate range -> [value-1, value+1]]",
            op=op,
            run_torch=lambda: torch_call(d_t, 4, 0, 0),
            run_c=lambda: c_module._aten_dispatch(op, d_c, 4, 0, 0),
            note="measured: [2,2,2] bins=4 -> [0,0,3,0], i.e. range [1,3], not [2,2]",
        )
    )

    # Refusals, both with upstream's exact wording (measured).
    e_t, e_c = pair_from_flat(torch_module, c_module, [1.0, 2.0], (2,), "float32")
    cases.append(
        Case(
            name="histc(bins=0) [refused]",
            op=op,
            run_torch=lambda: torch_call(e_t, 0, 0, 3),
            run_c=lambda: c_module._aten_dispatch(op, e_c, 0, 0, 3),
            expect="both_error",
            note="torch: 'bins must be > 0, but got 0 for dimension 0'",
        )
    )
    f_t, f_c = pair_from_flat(torch_module, c_module, [1.0, 2.0], (2,), "float32")
    cases.append(
        Case(
            name="histc(min > max, explicit) [refused]",
            op=op,
            run_torch=lambda: torch_call(f_t, 4, 3, 1),
            run_c=lambda: c_module._aten_dispatch(op, f_c, 4, 3, 1),
            expect="both_error",
            note="torch: 'torch.histc: max must be larger than min'",
        )
    )

    # Refused dtype: no CPU kernel for integral input, matching upstream's
    # exact wording.
    g_t, g_c = pair_from_flat(torch_module, c_module, [1, 2, 3], (3,), "int64")
    cases.append(
        Case(
            name="histc(dtype=int64) [refused -- histc has no CPU kernel for integral dtypes]",
            op=op,
            run_torch=lambda: torch_call(g_t, 4, 0, 3),
            run_c=lambda: c_module._aten_dispatch(op, g_c, 4, 0, 3),
            expect="both_error",
            note="torch: NotImplementedError('\"histogram_cpu\" not implemented for \\'Long\\'')",
        )
    )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # self/bins/min/max all by keyword.
    kw_t, kw_c = pair_from_flat(torch_module, c_module, [0.0, 1.0, 2.0, 3.0, 3.0, -1.0, 4.0], (7,), "float32")
    cases.append(
        Case(
            name="histc(self=/bins=/min=/max= all by keyword)",
            op=op,
            run_torch=lambda: torch_call(self=kw_t, bins=4, min=0, max=3),
            run_c=lambda: c_module._aten_dispatch(op, self=kw_c, bins=4, min=0, max=3),
        )
    )
    return cases


def clamp__default_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.clamp_.default"
    cases: list[Case] = []

    # mixtral's exact call shape: max only, min absent (None).
    for dtype_name in ["int64", "int32", "float32", "float64"]:
        a_t, a_c = pair_from_flat(torch_module, c_module, [1, 5, 10, -3], (4,), dtype_name)
        cases.append(
            Case(
                name=f"clamp_(dtype={dtype_name}, min=None, max=3) [mixtral's exact call shape]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, None, 3),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, None, 3),
                note="in-place: compares the mutated receiver clamp_ returns",
            )
        )

    for dtype_name in ["int64", "float32"]:
        b_t, b_c = pair_from_flat(torch_module, c_module, [1, 5, 10, -3], (4,), dtype_name)
        cases.append(
            Case(
                name=f"clamp_(dtype={dtype_name}, min=2, max=8)",
                op=op,
                run_torch=lambda b_t=b_t: torch_call(b_t, 2, 8),
                run_c=lambda b_c=b_c: c_module._aten_dispatch(op, b_c, 2, 8),
                note="both bounds present",
            )
        )

    # min > max: NOT refused -- collapses to a constant (measured formula
    # min(max(x,min_val),max_val), applied unconditionally regardless of
    # whether min_val <= max_val).
    c_t, c_c = pair_from_flat(torch_module, c_module, [1, 5, 10, -3], (4,), "int64")
    cases.append(
        Case(
            name="clamp_(min=8, max=2) [min > max collapses to a constant, NOT refused]",
            op=op,
            run_torch=lambda: torch_call(c_t, 8, 2),
            run_c=lambda: c_module._aten_dispatch(op, c_c, 8, 2),
            note="measured: [1,5,10,-3].clamp_(min=8,max=2) == [2,2,2,2]",
        )
    )

    # NaN propagates through both the floor and the ceiling.
    d_t, d_c = pair_from_flat(torch_module, c_module, [float("nan"), 1.0, -1.0], (3,), "float32")
    cases.append(
        Case(
            name="clamp_(dtype=float32, [nan,1.,-1.], min=0, max=2) [NaN propagates]",
            op=op,
            run_torch=lambda: torch_call(d_t, 0.0, 2.0),
            run_c=lambda: c_module._aten_dispatch(op, d_c, 0.0, 2.0),
            note="measured: [nan,1.,-1.].clamp_(0,2) == [nan,1.,0.]",
        )
    )

    # Both bounds absent: refused -- NOT a no-op. Measured on real torch
    # (naively guessable as "nothing to do, return self unchanged", and
    # wrong): `tensor.clamp_(None, None)` raises "At least one of 'min' or
    # 'max' must not be None".
    e_t, e_c = pair_from_flat(torch_module, c_module, [1.0, 2.0, 3.0], (3,), "float32")
    cases.append(
        Case(
            name="clamp_(min=None, max=None) [refused, NOT a no-op]",
            op=op,
            run_torch=lambda: torch_call(e_t, None, None),
            run_c=lambda: c_module._aten_dispatch(op, e_c, None, None),
            expect="both_error",
            note="torch: \"torch.clamp: At least one of 'min' or 'max' must not be None\"",
        )
    )

    # Refused: a float bound against an integral receiver, regardless of
    # whether the bound's value is exactly representable.
    f_t, f_c = pair_from_flat(torch_module, c_module, [1, 2, 3], (3,), "int32")
    cases.append(
        Case(
            name="clamp_(dtype=int32, max=2.0 [a FLOAT]) [refused, even though 2.0 is exact]",
            op=op,
            run_torch=lambda: torch_call(f_t, None, 2.0),
            run_c=lambda: c_module._aten_dispatch(op, f_c, None, 2.0),
            expect="both_error",
            note="torch: \"result type Float can't be cast to the desired output type Int\"",
        )
    )
    # `torch.bool` refuses on every spelling of the bounds, and the message
    # names the *bound's* type rather than the receiver's -- measured on
    # 2.13.0. It is cased because it used to compute: the kernel produced a
    # `uint8` replacement and `replace_with` retagged the receiver from
    # `torch.bool` to `torch.uint8`, which is computing where upstream refuses.
    # docs/VIEWS.md §6.8.
    for bounds, note in (
        ((0, 5), "torch: \"result type Long can't be cast to the desired output type bool\""),
        ((0.0, 1.0), "float bounds name Float in the same message"),
        ((None, 1), "one bound is enough"),
    ):
        b_t, b_c = pair_from_flat(
            torch_module, c_module, [True, False, True], (3,), "bool")
        cases.append(
            Case(
                name=f"clamp_(dtype=bool, min={bounds[0]}, max={bounds[1]}) [refused]",
                op=op,
                run_torch=lambda b_t=b_t, bounds=bounds: torch_call(b_t, *bounds),
                run_c=lambda b_c=b_c, bounds=bounds: c_module._aten_dispatch(op, b_c, *bounds),
                expect="both_error",
                note=note,
            )
        )
    # ...while `uint8`, the dtype `bool` shares candle storage with, computes.
    # The pair is what makes the refusal a statement about the *tag* rather
    # than about the bytes (BOOL.md §5-B).
    u_t, u_c = pair_from_flat(torch_module, c_module, [3, 5, 0], (3,), "uint8")
    cases.append(
        Case(
            name="clamp_(dtype=uint8, min=0, max=4) [computes -- the bool sibling does not]",
            op=op,
            run_torch=lambda: torch_call(u_t, 0, 4),
            run_c=lambda: c_module._aten_dispatch(op, u_c, 0, 4),
            note="bool and uint8 share candle's U8 storage and differ only in the tag",
        )
    )
    cases.extend(_clamp__member_cases(torch_module, c_module))
    cases.extend(
        c for c in _view_write_cases(torch_module, c_module)
        if c.op == "aten.clamp_.default"
    )
    return cases


def clamp_min_default_cases(torch_module, c_module, torch_call) -> list[Case]:
    """`aten.clamp_min(Tensor self, Scalar min)` -- vits' wall.

    The kernel shares `clamp`'s dtype ladder and `clamp`'s value formula, so
    the interesting question is not "does a floor work" but **"is it really the
    same ladder"**. The plausible wrong implementations are three, and each has
    a case here that separates it:

      * "a floor is `maximum`, so promote like a binary op" -- would make
        `clamp_min(int32, 2.0)` fail with the operand rule instead of giving
        `float32`, and would make `clamp_min(float16, 2.0)` `float32` instead
        of `float16`. Both rows are cased.
      * "`clamp_min` is `clamp(min=)`, so share the refusal wording too" --
        the bool-bound row's message names `clamp_min_scalar_cpu`, not
        `clamp_scalar_cpu`, and the case is `both_error` so the two sides only
        have to agree that it refuses; the wording is asserted in
        `pytests/test_shim.py`, where the string is visible.
      * "clamp both ends" -- a kernel that also applied a ceiling would pass
        every non-negative case, so `[1, 5, 10, -3]` with `min=2` is here:
        the answer keeps `10`.
    """
    op = "aten.clamp_min.default"
    cases: list[Case] = []

    # vits' exact call shape: a float32 sum, floored at the integer 1.
    v_t, v_c = pair_from_flat(torch_module, c_module, [0.25], (1,), "float32")
    cases.append(
        Case(
            name="clamp_min(float32(1,), 1) [vits' exact call shape]",
            op=op,
            run_torch=lambda: torch_call(v_t, 1),
            run_c=lambda: c_module._aten_dispatch(op, v_c, 1),
            note="modeling_vits.py:1352 clamp_min(sum(duration,[1,2]), 1).long()",
        )
    )

    # The values, across the dtypes the ladder does NOT move. `10` is in the
    # data so that a kernel which also clipped from above fails.
    for dtype_name in ["int64", "int32", "float32", "float64", "float16", "bfloat16"]:
        a_t, a_c = pair_from_flat(
            torch_module, c_module, [1, 5, 10, -3], (4,), dtype_name)
        cases.append(
            Case(
                name=f"clamp_min(dtype={dtype_name}, min=2) [10 must survive]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, 2),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, 2),
                note="a floor only; a kernel that also applied a ceiling loses the 10",
            )
        )

    # A negative floor, so that "clamp at zero" -- the shape most callers use
    # and the easiest thing to hardcode -- is separated.
    n_t, n_c = pair_from_flat(torch_module, c_module, [1, 5, -3, -9], (4,), "int64")
    cases.append(
        Case(
            name="clamp_min(dtype=int64, min=-1) [a NEGATIVE floor, not a relu]",
            op=op,
            run_torch=lambda: torch_call(n_t, -1),
            run_c=lambda: c_module._aten_dispatch(op, n_c, -1),
            note="measured [1,5,-3,-9] -> [1,5,-1,-1]; a relu would give [1,5,0,0]",
        )
    )

    # The dtype ladder. Each row was measured on 2.13.0 and each is a row
    # where a binary-promotion rule would answer differently.
    for dtype_name, bound, note in (
        ("int32", 2.0, "a float bound PROMOTES the out-of-place form (clamp_ refuses)"),
        ("uint8", 2, "an int bound leaves uint8 alone"),
        ("uint8", 2.0, "a float bound promotes uint8 to the default float"),
        ("float16", 2.0, "a python float never widens a float tensor -- stays float16"),
    ):
        b_t, b_c = pair_from_flat(torch_module, c_module, [1, 5, 3], (3,), dtype_name)
        cases.append(
            Case(
                name=f"clamp_min(dtype={dtype_name}, min={bound!r}) [dtype ladder]",
                op=op,
                run_torch=lambda b_t=b_t, bound=bound: torch_call(b_t, bound),
                run_c=lambda b_c=b_c, bound=bound: c_module._aten_dispatch(op, b_c, bound),
                note=note,
            )
        )

    # `bool` in: an int bound gives int64, a float bound gives float32, and a
    # *boolean* bound refuses -- the row that needs the raw argument rather
    # than the parsed Scalar, because `bool` subclasses `int` in Python.
    for bound, expect, note in (
        (0, "match", "measured: bool floored by an int is int64"),
        (0.0, "match", "measured: bool floored by a float is float32"),
        (False, "both_error", 'torch: "clamp_min_scalar_cpu" not implemented for \'Bool\''),
    ):
        b_t, b_c = pair_from_flat(
            torch_module, c_module, [True, False, True], (3,), "bool")
        cases.append(
            Case(
                name=f"clamp_min(dtype=bool, min={bound!r})",
                op=op,
                run_torch=lambda b_t=b_t, bound=bound: torch_call(b_t, bound),
                run_c=lambda b_c=b_c, bound=bound: c_module._aten_dispatch(op, b_c, bound),
                expect=expect,
                note=note,
            )
        )

    # NaN propagates: `maximum(nan, 0)` is `nan`, not `0`. A kernel written as
    # `where(x < min, min, x)` would answer `0` here, because `nan < 0` is
    # false -- no, it would answer `nan`; written as `where(x > min, x, min)`
    # it answers `min`, which is the wrong one. Measured: [nan, 1., -1.]
    # floored at 0 is [nan, 1., 0.].
    d_t, d_c = pair_from_flat(
        torch_module, c_module, [float("nan"), 1.0, -1.0], (3,), "float32")
    cases.append(
        Case(
            name="clamp_min(float32, [nan,1.,-1.], min=0) [NaN survives the floor]",
            op=op,
            run_torch=lambda: torch_call(d_t, 0.0),
            run_c=lambda: c_module._aten_dispatch(op, d_c, 0.0),
            note="measured [nan,1.,-1.] -> [nan,1.,0.]; `where(x > min, x, min)` gives 0",
        )
    )

    # The deliberate gap: `clamp_min.Tensor`. Upstream computes it (it is
    # `maximum` with broadcasting and binary promotion); this shim has no
    # `aten.maximum.default` to delegate to, so the overload is listed in both
    # tables with no kernel and refuses by name. Watched as `c_error` so that
    # the day it is implemented, this fails and gets promoted rather than
    # quietly starting to compute something unchecked.
    t_t, t_c = pair_from_flat(torch_module, c_module, [1.0, 5.0, -3.0], (3,), "float32")
    f_t, f_c = pair_from_flat(torch_module, c_module, [0.0, 6.0, -4.0], (3,), "float32")
    cases.append(
        Case(
            name="clamp_min(float32, min=Tensor) [c_error: clamp_min.Tensor has no kernel]",
            op=op,
            run_torch=lambda: _free(torch_module, "clamp_min")(t_t, f_t),
            run_c=lambda: _free(c_module, "clamp_min")(t_c, f_c),
            expect="c_error",
            note="listed in overloads.json/methods.json so it refuses by the overload's name",
        )
    )

    cases.extend(_clamp_min_member_cases(torch_module, c_module))
    return cases


def _clamp_min_member_cases(torch_module, c_module) -> list[Case]:
    """The two spellings vits and its neighbours actually use.

    `torch.clamp_min(x, 1)` is the one in `modeling_vits.py`; `x.clamp_min(1)`
    is the member. Golden compares by dispatch key and is structurally blind to
    both, so deleting either table entry fails here and nothing else.
    """
    op = "aten.clamp_min.default"
    cases: list[Case] = []
    for dtype_name in ["float32", "int64"]:
        pair = pair_from_flat(
            torch_module, c_module, [1, 5, 10, -3], (4,), dtype_name)
        cases.append(
            _member_case(
                torch_module, c_module, op,
                f"free torch.clamp_min(x, 2) (dtype={dtype_name})", dtype_name, [pair],
                lambda m, a: _free(m, "clamp_min")(a, 2),
                note="the free-function spelling vits uses; overloads.json entry",
            )
        )
        pair = pair_from_flat(
            torch_module, c_module, [1, 5, 10, -3], (4,), dtype_name)
        cases.append(
            _member_case(
                torch_module, c_module, op,
                f"member x.clamp_min(2) (dtype={dtype_name})", dtype_name, [pair],
                lambda m, a: a.clamp_min(2),
                note="the member spelling; methods.json entry",
            )
        )
    # The float32 sum vits floors, through the free function, followed by the
    # `.long()` the model actually does with it -- the two together are the
    # line, and the cast is where a wrong dtype from the ladder would surface
    # as a wrong integer rather than as a dtype mismatch.
    pair = pair_from_flat(torch_module, c_module, [0.25, 3.75], (2,), "float32")
    cases.append(
        _member_case(
            torch_module, c_module, op,
            "free torch.clamp_min(sum, 1).long() [vits' whole line]", "float32", [pair],
            lambda m, a: _free(m, "clamp_min")(a, 1).long(),
            note="measured [0.25, 3.75] -> [1., 3.75] -> [1, 3]; truncation, not rounding",
        )
    )
    return cases


def div__tensor_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.div_.Tensor"
    cases: list[Case] = []

    for dtype_name in ["float64", "float32", "float16", "bfloat16"]:
        a_t, a_c = pair_from_flat(torch_module, c_module, [1.0, 2.0, 3.0, 4.0, 5.0, 6.0], (3, 2), dtype_name)
        b_t, b_c = pair_from_flat(torch_module, c_module, [2.0, 4.0, 5.0], (3, 1), dtype_name)
        cases.append(
            Case(
                name=f"div_(dtype={dtype_name}, other (3,1) broadcasts into receiver (3,2))",
                op=op,
                run_torch=lambda a_t=a_t, b_t=b_t: torch_call(a_t, b_t),
                run_c=lambda a_c=a_c, b_c=b_c: c_module._aten_dispatch(op, a_c, b_c),
                note="mixtral's exact call shape: "
                     "top_k_weights.div_(top_k_weights.sum(-1, keepdim=True))",
            )
        )

    c_t, c_c = pair_from_flat(torch_module, c_module, [1.0, -1.0, 0.0, 5.0], (2, 2), "float32")
    d_t, d_c = pair_from_flat(torch_module, c_module, [0.0, 0.0, 0.0, 2.0], (2, 2), "float32")
    cases.append(
        Case(
            name="div_(dtype=float32, division by zero -- inf/-inf/nan, not an error)",
            op=op,
            run_torch=lambda: torch_call(c_t, d_t),
            run_c=lambda: c_module._aten_dispatch(op, c_c, d_c),
            note="in-place true division, IEEE 0-division rules, same as div.Tensor",
        )
    )

    # Refused: an integral receiver cannot hold the true-division result.
    e_t, e_c = pair_from_flat(torch_module, c_module, [1, 2, 3], (3,), "int64")
    f_t, f_c = pair_from_flat(torch_module, c_module, [2, 2, 2], (3,), "int64")
    cases.append(
        Case(
            name="div_(dtype=int64) [refused -- true division can't write back into int64]",
            op=op,
            run_torch=lambda: torch_call(e_t, f_t),
            run_c=lambda: c_module._aten_dispatch(op, e_c, f_c),
            expect="both_error",
            note="torch: \"result type Float can't be cast to the desired output type Long\"",
        )
    )

    # Refused: other's shape does not broadcast INTO the receiver's own
    # shape -- in-place can only shrink what's applied, never grow self.
    g_t, g_c = pair_from_flat(torch_module, c_module, [1.0, 2.0, 3.0], (3, 1), "float32")
    h_t, h_c = pair_from_flat(torch_module, c_module, [1.0, 2.0], (1, 2), "float32")
    cases.append(
        Case(
            name="div_(receiver (3,1), other (1,2)) [refused -- other would grow the receiver]",
            op=op,
            run_torch=lambda: torch_call(g_t, h_t),
            run_c=lambda: c_module._aten_dispatch(op, g_c, h_c),
            expect="both_error",
            note="torch: \"output with shape [3, 1] doesn't match the broadcast shape [3, 2]\"",
        )
    )
    cases.extend(_div__member_cases(torch_module, c_module))
    cases.extend(
        c for c in _view_write_cases(torch_module, c_module)
        if c.op == "aten.div_.Tensor"
    )
    return cases


def masked_fill__scalar_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.masked_fill_.Scalar"
    cases: list[Case] = []
    # Same bool-mask construction workaround `masked_fill_cases` documents
    # above -- `_C`'s `_tensor_from_flat` refuses to build a bool tensor
    # directly, so the mask is built from an int 0/1 flat list with an
    # explicit `dtype=c_module.bool`.
    a_flat, a_shape = [1.0, 2.0, 3.0, 4.0, 5.0, 6.0], (2, 3)
    mask_flat = [True, False, True, False, True, False]
    for dtype_name in ["float64", "float32", "float16", "bfloat16"]:
        big = _FLOAT_ADD_MAGNITUDE[dtype_name]
        for value, note in [
            (0.0, "zero fill"),
            (-big, "large negative -- sentinel masking, mixtral's exact use"),
        ]:
            cases.append(
                Case(
                    name=f"masked_fill_(dtype={dtype_name}, value={value}) [in-place]",
                    op=op,
                    run_torch=lambda dtype_name=dtype_name, value=value: torch_call(
                        torch_module.tensor(a_flat, dtype=dt.torch_dtype(torch_module, dtype_name)).reshape(
                            list(a_shape)
                        ),
                        torch_module.tensor(mask_flat).reshape(list(a_shape)),
                        value,
                    ),
                    run_c=lambda dtype_name=dtype_name, value=value: c_module._aten_dispatch(
                        op,
                        c_module._tensor_from_flat(a_flat, list(a_shape), dtype=dt.c_dtype(c_module, dtype_name)),
                        c_module._tensor_from_flat([int(v) for v in mask_flat], list(a_shape), dtype=c_module.bool),
                        value,
                    ),
                    note=note,
                )
            )

    # Broadcasting mask -- mixtral's exact shape: `sentinel_mask` is
    # `(N,1)`, the receiver is `(N,hidden_dim)`.
    b_flat = [float(v) for v in range(1, 9)]
    b_shape = (4, 2)
    bmask_flat = [True, False, True, False]
    cases.append(
        Case(
            name="masked_fill_(dtype=float32, mask (4,1) broadcasts into receiver (4,2))",
            op=op,
            run_torch=lambda: torch_call(
                torch_module.tensor(b_flat).reshape(list(b_shape)),
                torch_module.tensor(bmask_flat).reshape([4, 1]),
                -1.0,
            ),
            run_c=lambda: c_module._aten_dispatch(
                op,
                c_module._tensor_from_flat(b_flat, list(b_shape), dtype=c_module.float32),
                c_module._tensor_from_flat([int(v) for v in bmask_flat], [4, 1], dtype=c_module.bool),
                -1.0,
            ),
            note="mixtral's exact call shape: "
                 "selected_hidden_states_g.masked_fill_(sentinel_mask, 0.0)",
        )
    )
    cases.extend(_masked_fill__member_cases(torch_module, c_module))
    cases.extend(
        c for c in _view_write_cases(torch_module, c_module)
        if c.op == "aten.masked_fill_.Scalar"
    )
    return cases


def index_put__cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.index_put_.default"
    cases: list[Case] = []

    # mixtral's exact call shape: inv_perm[perm] = torch.arange(perm.size(0))
    # -- a single int64 index tensor, no accumulate, 1-D self/index/values.
    for dtype_name in ["int64", "int32", "float32"]:
        zero_flat = [0.0] * 5 if dtype_name == "float32" else [0] * 5
        values_flat = [10.0, 20.0, 30.0, 40.0, 50.0] if dtype_name == "float32" else [10, 20, 30, 40, 50]
        self_t, self_c = pair_from_flat(torch_module, c_module, zero_flat, (5,), dtype_name)
        idx_t, idx_c = pair_from_flat(torch_module, c_module, [4, 3, 2, 1, 0], (5,), "int64")
        values_t, values_c = pair_from_flat(torch_module, c_module, values_flat, (5,), dtype_name)
        cases.append(
            Case(
                name=f"index_put_(dtype={dtype_name}, self[index]=values, no accumulate)",
                op=op,
                run_torch=lambda self_t=self_t, idx_t=idx_t, values_t=values_t: torch_call(
                    self_t, [idx_t], values_t, False
                ),
                run_c=lambda self_c=self_c, idx_c=idx_c, values_c=values_c: c_module._aten_dispatch(
                    op, self_c, [idx_c], values_c, False
                ),
                note="mixtral's exact call shape: inv_perm[perm] = torch.arange(perm.size(0))",
            )
        )

    # Repeated index -- last write wins (measured), the same rule
    # `scatter.src`'s doc comment already documents and this reuses.
    self2_t, self2_c = pair_from_flat(torch_module, c_module, [0, 0, 0], (3,), "int64")
    idx2_t, idx2_c = pair_from_flat(torch_module, c_module, [0, 0, 0], (3,), "int64")
    values2_t, values2_c = pair_from_flat(torch_module, c_module, [1, 2, 3], (3,), "int64")
    cases.append(
        Case(
            name="index_put_(repeated index) [last write wins]",
            op=op,
            run_torch=lambda: torch_call(self2_t, [idx2_t], values2_t, False),
            run_c=lambda: c_module._aten_dispatch(op, self2_c, [idx2_c], values2_c, False),
            note="measured: index [0,0,0] with values [1,2,3] leaves self[0] == 3",
        )
    )

    # --- the bool mask (docs/VIEWS.md §2) ---------------------------------
    #
    # A mask is a different operation from an integer index, not a cast: it
    # selects the positions where it is true. This was a `c_error` case for as
    # long as the kernel delegated to `scatter`, which refused the dtype
    # ("Expected dtype int32 or int64 for index, got bool"). It computes now,
    # so it is a real case and the values are diffed.
    for mask_dtype in ["bool", "uint8"]:
        m_self_t, m_self_c = pair_from_flat(torch_module, c_module, [0.0] * 4, (4,), "float32")
        m_mask_t, m_mask_c = pair_from_flat(torch_module, c_module, [1, 0, 1, 0], (4,), mask_dtype)
        m_val_t, m_val_c = pair_from_flat(torch_module, c_module, [1.0, 2.0], (2,), "float32")
        cases.append(
            Case(
                name=f"index_put_(1-D {mask_dtype} mask, values one per true position)",
                op=op,
                run_torch=lambda a=m_self_t, m=m_mask_t, v=m_val_t: torch_call(a, [m], v, False),
                run_c=lambda a=m_self_c, m=m_mask_c, v=m_val_c: c_module._aten_dispatch(op, a, [m], v, False),
                note="upstream treats uint8 as a deprecated spelling of bool and gathers the "
                     "TRUE positions, not the positions the values name -- the same rule "
                     "index.Tensor's doc comment records",
            )
        )
    # A 0-d value against a mask: every true position gets the same number.
    m2_self_t, m2_self_c = pair_from_flat(torch_module, c_module, [0.0] * 4, (4,), "float32")
    m2_mask_t, m2_mask_c = pair_from_flat(torch_module, c_module, [1, 0, 1, 0], (4,), "bool")
    m2_val_t, m2_val_c = pair_from_flat(torch_module, c_module, [5.0], (), "float32")
    cases.append(
        Case(
            name="index_put_(1-D bool mask, 0-d values broadcast)",
            op=op,
            run_torch=lambda: torch_call(m2_self_t, [m2_mask_t], m2_val_t, False),
            run_c=lambda: c_module._aten_dispatch(op, m2_self_c, [m2_mask_c], m2_val_c, False),
            note="x[mask] = 5.0 -- the shape __setitem__ produces for a number",
        )
    )
    # A mask covering BOTH axes of a matrix writes n scalars; a mask covering
    # only the first writes whole rows. Two different results from the same
    # receiver, which is what says the mask's rank is being read.
    m3_self_t, m3_self_c = pair_from_flat(torch_module, c_module, [0.0] * 6, (2, 3), "float32")
    m3_mask_t, m3_mask_c = pair_from_flat(torch_module, c_module, [1, 0, 1, 0, 1, 0], (2, 3), "bool")
    m3_val_t, m3_val_c = pair_from_flat(torch_module, c_module, [1.0, 2.0, 3.0], (3,), "float32")
    cases.append(
        Case(
            name="index_put_(2-D bool mask over a 2-D self) [the mask consumes both axes]",
            op=op,
            run_torch=lambda: torch_call(m3_self_t, [m3_mask_t], m3_val_t, False),
            run_c=lambda: c_module._aten_dispatch(op, m3_self_c, [m3_mask_c], m3_val_c, False),
            note="three true positions, three values, one each -- measured [[1,0,2],[0,3,0]]",
        )
    )
    m4_self_t, m4_self_c = pair_from_flat(torch_module, c_module, [0.0] * 6, (2, 3), "float32")
    m4_mask_t, m4_mask_c = pair_from_flat(torch_module, c_module, [1, 0], (2,), "bool")
    m4_val_t, m4_val_c = pair_from_flat(torch_module, c_module, [1.0, 2.0, 3.0], (3,), "float32")
    cases.append(
        Case(
            name="index_put_(1-D bool mask over a 2-D self) [the mask consumes one axis, so a row]",
            op=op,
            run_torch=lambda: torch_call(m4_self_t, [m4_mask_t], m4_val_t, False),
            run_c=lambda: c_module._aten_dispatch(op, m4_self_c, [m4_mask_c], m4_val_c, False),
            note="one true position selecting a whole row -- measured [[1,2,3],[0,0,0]]. "
                 "Same mask values as the 2-D case above and a different answer, which is "
                 "what pins the rank read rather than the contents",
        )
    )
    # An all-false mask writes nothing. Upstream returns self unchanged rather
    # than refusing on the zero-length value.
    m5_self_t, m5_self_c = pair_from_flat(torch_module, c_module, [1.0, 2.0, 3.0, 4.0], (4,), "float32")
    m5_mask_t, m5_mask_c = pair_from_flat(torch_module, c_module, [0, 0, 0, 0], (4,), "bool")
    m5_val_t, m5_val_c = pair_from_flat(torch_module, c_module, [], (0,), "float32")
    cases.append(
        Case(
            name="index_put_(all-false mask, empty values) [writes nothing, returns self]",
            op=op,
            run_torch=lambda: torch_call(m5_self_t, [m5_mask_t], m5_val_t, False),
            run_c=lambda: c_module._aten_dispatch(op, m5_self_c, [m5_mask_c], m5_val_c, False),
            note="measured: no write and no refusal. The receiver is non-zero so a kernel "
                 "that zeroed it, or one that refused, both fail here",
        )
    )
    # A mask whose shape does not line up: upstream raises, naming the
    # mismatching axis twice. `mask_to_indices` owns that message already.
    m6_self_t, m6_self_c = pair_from_flat(torch_module, c_module, [0.0] * 4, (4,), "float32")
    m6_mask_t, m6_mask_c = pair_from_flat(torch_module, c_module, [1, 0, 1], (3,), "bool")
    m6_val_t, m6_val_c = pair_from_flat(torch_module, c_module, [1.0, 2.0], (2,), "float32")
    cases.append(
        Case(
            name="index_put_(mask shorter than the axis it covers) [both refuse]",
            op=op,
            run_torch=lambda: torch_call(m6_self_t, [m6_mask_t], m6_val_t, False),
            run_c=lambda: c_module._aten_dispatch(op, m6_self_c, [m6_mask_c], m6_val_c, False),
            expect="both_error",
            note="torch: IndexError('The shape of the mask [3] at index 0 does not match the "
                 "shape of the indexed tensor [4] at index 0'), reproduced verbatim",
        )
    )

    # --- self of rank above 1 (docs/VIEWS.md §3) ---------------------------
    #
    # `x[idx] = v` on a matrix, which is the common case and which the
    # scatter-based kernel refused outright ("only a 1-D self/index/values").
    # The indexing result here is (2,2): two selected rows of width two, and
    # `values` broadcasts onto it right-aligned.
    for label, v_flat, v_shape, note in [
        ("0-d", [5.0], (), "x[idx] = 5 -- one number into every selected element"),
        ("(2,2)", [1.0, 2.0, 3.0, 4.0], (2, 2), "one value per written element, no broadcast"),
        ("(2,)", [1.0, 2.0], (2,), "right-aligned: the row is reused for both selected rows"),
        ("(2,1)", [1.0, 2.0], (2, 1), "the OTHER broadcast of the same two numbers -- (2,) "
                                      "fills across and (2,1) fills down, so a kernel that "
                                      "aligned left would swap these two answers"),
    ]:
        r_self_t, r_self_c = pair_from_flat(torch_module, c_module, [0.0] * 6, (3, 2), "float32")
        r_idx_t, r_idx_c = pair_from_flat(torch_module, c_module, [0, 2], (2,), "int64")
        r_val_t, r_val_c = pair_from_flat(torch_module, c_module, v_flat, v_shape, "float32")
        cases.append(
            Case(
                name=f"index_put_(self (3,2), index (2,), values {label})",
                op=op,
                run_torch=lambda a=r_self_t, i=r_idx_t, v=r_val_t: torch_call(a, [i], v, False),
                run_c=lambda a=r_self_c, i=r_idx_c, v=r_val_c: c_module._aten_dispatch(op, a, [i], v, False),
                note=note,
            )
        )
    # ...and the value that does not fit, which upstream names precisely.
    r2_self_t, r2_self_c = pair_from_flat(torch_module, c_module, [0.0] * 6, (3, 2), "float32")
    r2_idx_t, r2_idx_c = pair_from_flat(torch_module, c_module, [0, 2], (2,), "int64")
    r2_val_t, r2_val_c = pair_from_flat(torch_module, c_module, [1.0, 2.0, 3.0], (3,), "float32")
    cases.append(
        Case(
            name="index_put_(values that do not broadcast onto the indexing result) [both refuse]",
            op=op,
            run_torch=lambda: torch_call(r2_self_t, [r2_idx_t], r2_val_t, False),
            run_c=lambda: c_module._aten_dispatch(op, r2_self_c, [r2_idx_c], r2_val_c, False),
            expect="both_error",
            note="torch: RuntimeError('shape mismatch: value tensor of shape [3] cannot be "
                 "broadcast to indexing result of shape [2, 2]'), reproduced verbatim",
        )
    )
    # An index tensor at a later axis: the `[None, t]` list `x[:, t] = v`
    # produces. The indexing result is (2,2) again but for a different reason,
    # and a kernel that ignored the leading `None` would write down the first
    # column instead of across.
    n_self_t, n_self_c = pair_from_flat(torch_module, c_module, [0.0] * 6, (2, 3), "float32")
    n_idx_t, n_idx_c = pair_from_flat(torch_module, c_module, [0, 2], (2,), "int64")
    n_val_t, n_val_c = pair_from_flat(torch_module, c_module, [1.0, 2.0, 3.0, 4.0], (2, 2), "float32")
    cases.append(
        Case(
            name="index_put_(self (2,3), indices [None, index]) [the index sits at axis 1]",
            op=op,
            run_torch=lambda: torch_call(n_self_t, [None, n_idx_t], n_val_t, False),
            run_c=lambda: c_module._aten_dispatch(op, n_self_c, [None, n_idx_c], n_val_c, False),
            note="measured [[1,0,2],[3,0,4]] -- columns 0 and 2 of both rows, in row-major "
                 "order over the (2,2) result",
        )
    )
    # An index tensor that is not 1-D. Its shape is spliced into the result
    # whole, so a (2,2) index over a (4,2) self gives a (2,2,2) result.
    s_self_t, s_self_c = pair_from_flat(torch_module, c_module, [0.0] * 8, (4, 2), "float32")
    s_idx_t, s_idx_c = pair_from_flat(torch_module, c_module, [0, 1, 2, 3], (2, 2), "int64")
    s_val_t, s_val_c = pair_from_flat(
        torch_module, c_module, [0.0, 1.0, 2.0, 3.0, 4.0, 5.0, 6.0, 7.0], (2, 2, 2), "float32"
    )
    cases.append(
        Case(
            name="index_put_(2-D index over a 2-D self) [the index shape is spliced in whole]",
            op=op,
            run_torch=lambda: torch_call(s_self_t, [s_idx_t], s_val_t, False),
            run_c=lambda: c_module._aten_dispatch(op, s_self_c, [s_idx_c], s_val_c, False),
            note="indexing result (2,2,2); the values arrive already the right shape, so "
                 "this pins the row-major ORDER of the walk and nothing else",
        )
    )

    # --- negative and out-of-range indices ---------------------------------
    #
    # torch wraps a negative index here. The scatter-based kernel could not:
    # `scatter` has no negative-index rule and refused these as out of bounds.
    g_self_t, g_self_c = pair_from_flat(torch_module, c_module, [0.0] * 5, (5,), "float32")
    g_idx_t, g_idx_c = pair_from_flat(torch_module, c_module, [-1, -2], (2,), "int64")
    g_val_t, g_val_c = pair_from_flat(torch_module, c_module, [1.0, 2.0], (2,), "float32")
    cases.append(
        Case(
            name="index_put_(negative indices wrap) [-1 is the last position]",
            op=op,
            run_torch=lambda: torch_call(g_self_t, [g_idx_t], g_val_t, False),
            run_c=lambda: c_module._aten_dispatch(op, g_self_c, [g_idx_c], g_val_c, False),
            note="measured [0,0,0,2,1] -- the two are in the reverse of the order they "
                 "appear, so a kernel that clamped instead of wrapping fails here",
        )
    )
    for label, bad in [("above the extent", 9), ("below the extent", -9)]:
        b_self_t, b_self_c = pair_from_flat(torch_module, c_module, [0.0] * 5, (5,), "float32")
        b_idx_t, b_idx_c = pair_from_flat(torch_module, c_module, [bad], (1,), "int64")
        b_val_t, b_val_c = pair_from_flat(torch_module, c_module, [1.0], (1,), "float32")
        cases.append(
            Case(
                name=f"index_put_(index {label}) [both refuse]",
                op=op,
                run_torch=lambda a=b_self_t, i=b_idx_t, v=b_val_t: torch_call(a, [i], v, False),
                run_c=lambda a=b_self_c, i=b_idx_c, v=b_val_c: c_module._aten_dispatch(op, a, [i], v, False),
                expect="both_error",
                note=f"torch: IndexError('index {bad} is out of bounds for dimension 0 with "
                     "size 5'), reproduced verbatim -- and note -9 is refused rather than "
                     "wrapped twice",
            )
        )
    # An empty index writes nothing rather than refusing on the empty value.
    e_self_t, e_self_c = pair_from_flat(torch_module, c_module, [1.0, 2.0, 3.0], (3,), "float32")
    e_idx_t, e_idx_c = pair_from_flat(torch_module, c_module, [], (0,), "int64")
    e_val_t, e_val_c = pair_from_flat(torch_module, c_module, [], (0,), "float32")
    cases.append(
        Case(
            name="index_put_(empty index) [writes nothing, returns self]",
            op=op,
            run_torch=lambda: torch_call(e_self_t, [e_idx_t], e_val_t, False),
            run_c=lambda: c_module._aten_dispatch(op, e_self_c, [e_idx_c], e_val_c, False),
            note="measured: no write and no refusal, with the receiver left non-zero",
        )
    )

    # --- dtypes ------------------------------------------------------------
    #
    # Upstream does NOT promote here; it names both sides and refuses.
    d_self_t, d_self_c = pair_from_flat(torch_module, c_module, [0.0] * 3, (3,), "float32")
    d_idx_t, d_idx_c = pair_from_flat(torch_module, c_module, [0], (1,), "int64")
    d_val_t, d_val_c = pair_from_flat(torch_module, c_module, [1], (1,), "int64")
    cases.append(
        Case(
            name="index_put_(float32 self, int64 values) [both refuse -- no promotion]",
            op=op,
            run_torch=lambda: torch_call(d_self_t, [d_idx_t], d_val_t, False),
            run_c=lambda: c_module._aten_dispatch(op, d_self_c, [d_idx_c], d_val_c, False),
            expect="both_error",
            note="torch: RuntimeError('Index put requires the source and destination dtypes "
                 "match, got Float for the destination and Long for the source.')",
        )
    )
    # An int32 index is accepted, as it is for `scatter` and `index.Tensor`.
    i32_self_t, i32_self_c = pair_from_flat(torch_module, c_module, [0.0] * 3, (3,), "float32")
    i32_idx_t, i32_idx_c = pair_from_flat(torch_module, c_module, [0, 2], (2,), "int32")
    i32_val_t, i32_val_c = pair_from_flat(torch_module, c_module, [1.0, 2.0], (2,), "float32")
    cases.append(
        Case(
            name="index_put_(int32 index) [accepted, like scatter's]",
            op=op,
            run_torch=lambda: torch_call(i32_self_t, [i32_idx_t], i32_val_t, False),
            run_c=lambda: c_module._aten_dispatch(op, i32_self_c, [i32_idx_c], i32_val_c, False),
            note="measured: int32 is not refused here, unlike a float index",
        )
    )
    # A bool receiver, which is the one dtype whose storage tag can be lost on
    # the way back out of the kernel (BOOL.md §6.3).
    bl_self_t, bl_self_c = pair_from_flat(torch_module, c_module, [0, 0, 0, 0], (4,), "bool")
    bl_idx_t, bl_idx_c = pair_from_flat(torch_module, c_module, [0, 2], (2,), "int64")
    bl_val_t, bl_val_c = pair_from_flat(torch_module, c_module, [1, 1], (2,), "bool")
    cases.append(
        Case(
            name="index_put_(bool self and bool values) [the tag survives the write]",
            op=op,
            run_torch=lambda: torch_call(bl_self_t, [bl_idx_t], bl_val_t, False),
            run_c=lambda: c_module._aten_dispatch(op, bl_self_c, [bl_idx_c], bl_val_c, False),
            note="the comparator checks dtype as well as values, so a result that came back "
                 "as uint8 fails here rather than reading as 0/1 and passing",
        )
    )
    # A float index, which upstream refuses by naming the four it accepts.
    f_self_t, f_self_c = pair_from_flat(torch_module, c_module, [0.0] * 3, (3,), "float32")
    f_idx_t, f_idx_c = pair_from_flat(torch_module, c_module, [0.0], (1,), "float32")
    f_val_t, f_val_c = pair_from_flat(torch_module, c_module, [1.0], (1,), "float32")
    cases.append(
        Case(
            name="index_put_(float index) [both refuse]",
            op=op,
            run_torch=lambda: torch_call(f_self_t, [f_idx_t], f_val_t, False),
            run_c=lambda: c_module._aten_dispatch(op, f_self_c, [f_idx_c], f_val_c, False),
            expect="both_error",
            note="torch: IndexError('tensors used as indices must be long, int, byte or "
                 "bool tensors'), reproduced verbatim",
        )
    )

    # --- the mutation itself -----------------------------------------------
    #
    # `index_put_` RETURNS `self`, so every case above reads the return value
    # and could not tell a write-through from a freshly built tensor handed
    # back. These two throw the return value away and read the binding that
    # was passed in. A kernel that computed the right answer and forgot to
    # `replace_with` passes everything above and fails here.
    for label, dtype_name, flat, shape, idx_flat, idx_shape, val_flat, val_shape in [
        ("1-D", "float32", [0.0] * 5, (5,), [0, 2, 4], (3,), [7.0, 8.0, 9.0], (3,)),
        ("2-D", "float32", [0.0] * 6, (3, 2), [0, 2], (2,), [5.0], ()),
    ]:
        a_self_t, a_self_c = pair_from_flat(torch_module, c_module, flat, shape, dtype_name)
        a_idx_t, a_idx_c = pair_from_flat(torch_module, c_module, idx_flat, idx_shape, "int64")
        a_val_t, a_val_c = pair_from_flat(torch_module, c_module, val_flat, val_shape, dtype_name)

        def _through_torch(a=a_self_t, i=a_idx_t, v=a_val_t):
            torch_call(a, [i], v, False)
            return a

        def _through_c(a=a_self_c, i=a_idx_c, v=a_val_c):
            c_module._aten_dispatch(op, a, [i], v, False)
            return a

        cases.append(
            Case(
                name=f"index_put_({label} self, read back through the ORIGINAL binding)",
                op=op,
                run_torch=_through_torch,
                run_c=_through_c,
                note="the return value is discarded; this is the only case shape that can "
                     "fail when the write lands in a copy",
            )
        )

    # Refused: accumulate=True is not measured/implemented.
    self3_t, self3_c = pair_from_flat(torch_module, c_module, [0, 0, 0], (3,), "int64")
    idx3_t, idx3_c = pair_from_flat(torch_module, c_module, [0, 1, 2], (3,), "int64")
    values3_t, values3_c = pair_from_flat(torch_module, c_module, [1, 2, 3], (3,), "int64")
    cases.append(
        Case(
            name="index_put_(accumulate=True) [c_error -- torch computes, shim refuses]",
            op=op,
            run_torch=lambda: torch_call(self3_t, [idx3_t], values3_t, True),
            run_c=lambda: c_module._aten_dispatch(op, self3_c, [idx3_c], values3_c, True),
            expect="c_error",
            note="torch computes accumulate=True; the shim refuses it by name (not measured/needed)",
        )
    )

    # Keyword-argument coverage (docs/GOLDEN.md, docs/DISPATCH.md §4.1):
    # self/indices/values/accumulate all by keyword.
    kw_self_t, kw_self_c = pair_from_flat(torch_module, c_module, [0.0] * 5, (5,), "float32")
    kw_idx_t, kw_idx_c = pair_from_flat(torch_module, c_module, [4, 3, 2, 1, 0], (5,), "int64")
    kw_val_t, kw_val_c = pair_from_flat(torch_module, c_module, [10.0, 20.0, 30.0, 40.0, 50.0], (5,), "float32")
    cases.append(
        Case(
            name="index_put_(self=/indices=/values=/accumulate= all by keyword)",
            op=op,
            run_torch=lambda: torch_call(self=kw_self_t, indices=[kw_idx_t], values=kw_val_t, accumulate=False),
            run_c=lambda: c_module._aten_dispatch(
                op, self=kw_self_c, indices=[kw_idx_c], values=kw_val_c, accumulate=False
            ),
        )
    )
    cases.extend(
        c for c in _setitem_member_cases(torch_module, c_module)
        if c.op == "aten.index_put_.default"
    )
    cases.extend(
        c for c in _view_write_cases(torch_module, c_module)
        if c.op == "aten.index_put_.default"
    )
    return cases


# --- aten.abs.default / aten.ceil.default / aten.gt.{Scalar,Tensor} /
#     aten.masked_select.default / aten.min.default / aten.unbind.int -------
#
# The six ops `repr(tensor)` dispatches that this shim lacked -- measured
# with a `TorchDispatchMode` logger wrapped around
# `torch._tensor_str._str_intern` and diffed against `_aten_implemented()`.
# rust/torch_c is landing kernels for these concurrently with this change;
# they may not appear in `_aten_implemented()` yet (see the "PENDING"
# printout in compare.py's `run()`), which is expected -- the point of
# adding builders now is that the harness fails loudly, not silently, the
# moment each kernel lands without one.


def abs_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.abs.default"
    cases: list[Case] = []
    for dtype_name in _TRIG_DTYPES:
        cases.append(_unary_case(torch_module, c_module, op, torch_call, dtype_name, [1.0, -2.0, 0.0, 0.5], (2, 2), "assorted signs"))
        cases.append(_unary_case(torch_module, c_module, op, torch_call, dtype_name, [-0.0], (), "-0.0 abs's to 0.0 (measured)"))
        cases.append(
            _unary_case(
                torch_module, c_module, op, torch_call, dtype_name,
                [float("inf"), float("-inf"), float("nan")], (3,),
                "inf/nan: both infinities become +inf, nan stays nan (measured)",
            )
        )

    # Signed integers, including each dtype's most-negative value. That value
    # has no positive representation, and upstream's abs() wraps it straight
    # back to itself instead of refusing (measured) -- the same two's
    # complement wraparound `neg_cases` and `_FULL_FILLS["int32"]` already
    # pin elsewhere in this file, not a new discrepancy.
    _ABS_INT_MIN = {"int64": -9223372036854775808, "int32": -2147483648, "int16": -32768}
    for dtype_name in ["int64", "int32", "int16"]:
        cases.append(_unary_case(torch_module, c_module, op, torch_call, dtype_name, [1, -2, 0, 7], (2, 2), "signed integers"))
        cases.append(
            _unary_case(
                torch_module, c_module, op, torch_call, dtype_name, [_ABS_INT_MIN[dtype_name]], (1,),
                f"{dtype_name} min has no positive representation -- abs() wraps back to "
                "the same negative value upstream (measured), it does not raise",
            )
        )
    cases.append(_unary_case(torch_module, c_module, op, torch_call, "uint8", [0, 1, 255], (3,), "unsigned: abs is the identity"))

    cases.append(
        Case(
            name="abs(dtype=bool) [torch refuses]",
            op=op,
            run_torch=lambda: torch_call(torch_module.tensor([True, False])),
            run_c=lambda: c_module._aten_dispatch(op, c_module._tensor_from_flat([1, 0], [2], dtype=c_module.bool)),
            expect="both_error",
            note="torch: NotImplementedError(\"abs_cpu\" not implemented for 'Bool') (measured)",
        )
    )
    return cases


def ceil_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.ceil.default"
    cases: list[Case] = []
    for dtype_name in _TRIG_DTYPES:
        cases.append(
            _unary_case(
                torch_module, c_module, op, torch_call, dtype_name,
                [1.2, -1.2, -0.5, 0.5, 2.0, -2.0], (2, 3),
                "fractional values, including -0.5 -- torch gives -0., not 0. (measured)",
            )
        )
        cases.append(
            _unary_case(
                torch_module, c_module, op, torch_call, dtype_name,
                [1.0, -1.0, 0.0, 5.0], (2, 2), "already-integral values are a no-op",
            )
        )
        cases.append(
            _unary_case(
                torch_module, c_module, op, torch_call, dtype_name,
                [float("inf"), float("-inf"), float("nan")], (3,), "inf/nan pass through unchanged (measured)",
            )
        )

    # Integer dtypes: ceil is an identity, not a refusal (measured) -- unlike
    # `abs`/`neg` there is no sign/overflow question here, so no dtype-min case.
    for dtype_name in ["int64", "int32", "int16", "uint8"]:
        flat = [1, 2, 3] if dtype_name == "uint8" else [1, -2, 3]
        cases.append(_unary_case(torch_module, c_module, op, torch_call, dtype_name, flat, (3,), "integers: ceil is the identity (measured)"))

    cases.append(
        Case(
            name="ceil(dtype=bool) [torch refuses]",
            op=op,
            run_torch=lambda: torch_call(torch_module.tensor([True, False])),
            run_c=lambda: c_module._aten_dispatch(op, c_module._tensor_from_flat([1, 0], [2], dtype=c_module.bool)),
            expect="both_error",
            note="torch: NotImplementedError(\"ceil_vml_cpu\" not implemented for 'Bool') (measured)",
        )
    )
    return cases


def gt_tensor_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.gt.Tensor"
    cases: list[Case] = []
    for dtype_name in _CMP_DTYPES:
        for sc in _CMP_SCENARIOS:
            cases.append(
                _binary_tensor_case(
                    torch_module, c_module, op, torch_call, dtype_name,
                    sc["a_flat"], sc["a_shape"], sc["b_flat"], sc["b_shape"], sc["note"],
                )
            )
    cases.append(
        Case(
            name="gt(int64, x > x is False) [equality boundary]",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [1, 2, 3], (3,), "int64")[0],
                _pair(torch_module, c_module, [1, 2, 3], (3,), "int64")[0],
            ),
            run_c=lambda: c_module._aten_dispatch(
                op,
                _pair(torch_module, c_module, [1, 2, 3], (3,), "int64")[1],
                _pair(torch_module, c_module, [1, 2, 3], (3,), "int64")[1],
            ),
            note="every element compared against itself -- strict >, so all False",
        )
    )
    cases.append(
        Case(
            name="gt(float32, nan > nan and nan > 1.0) [every comparison against NaN is false]",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [float("nan"), 3.0, 2.0], (3,), "float32")[0],
                _pair(torch_module, c_module, [float("nan"), 2.0, float("nan")], (3,), "float32")[0],
            ),
            run_c=lambda: c_module._aten_dispatch(
                op,
                _pair(torch_module, c_module, [float("nan"), 3.0, 2.0], (3,), "float32")[1],
                _pair(torch_module, c_module, [float("nan"), 2.0, float("nan")], (3,), "float32")[1],
            ),
            note="NaN on either side (or both) makes that element False, even 3.0 > nan",
        )
    )
    cases.append(
        Case(
            name="gt(bool, [T,F,T] > [F,F,T]) [bool compares as 0/1]",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [1, 0, 1], (3,), "bool")[0],
                _pair(torch_module, c_module, [0, 0, 1], (3,), "bool")[0],
            ),
            run_c=lambda: c_module._aten_dispatch(
                op,
                _pair(torch_module, c_module, [1, 0, 1], (3,), "bool")[1],
                _pair(torch_module, c_module, [0, 0, 1], (3,), "bool")[1],
            ),
            note="True > False is True, True > True is False (measured)",
        )
    )
    return cases


def gt_scalar_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.gt.Scalar"
    cases: list[Case] = []
    for dtype_name in _CMP_DTYPES:
        cases.append(
            _binary_scalar_case(
                torch_module, c_module, op, torch_call, dtype_name,
                [1, 2, 3, 4], (2, 2), 3, "x > 3, as reached from __gt__ with a python scalar",
            )
        )
    cases.append(
        Case(
            name="gt(int64, x > 4) [equality boundary -- 4 itself is not > 4]",
            op=op,
            run_torch=lambda: torch_call(_pair(torch_module, c_module, [1, 2, 3, 4], (2, 2), "int64")[0], 4),
            run_c=lambda: c_module._aten_dispatch(op, _pair(torch_module, c_module, [1, 2, 3, 4], (2, 2), "int64")[1], 4),
            note="the largest element equals the scalar -- strict >, so it is False",
        )
    )
    cases.append(
        Case(
            name="gt(int64 tensor, float scalar 2.5) [int-vs-float scalar]",
            op=op,
            run_torch=lambda: torch_call(_pair(torch_module, c_module, [1, 2, 3], (3,), "int64")[0], 2.5),
            run_c=lambda: c_module._aten_dispatch(op, _pair(torch_module, c_module, [1, 2, 3], (3,), "int64")[1], 2.5),
            note="a float Scalar against an int tensor -- torch compares numerically, "
                 "no dtype promotion of the result (still bool) (measured)",
        )
    )
    cases.append(
        Case(
            name="gt(float32, nan > 1.0) [every comparison against NaN is false]",
            op=op,
            run_torch=lambda: torch_call(
                _pair(torch_module, c_module, [float("nan"), 1.0], (2,), "float32")[0], 1.0
            ),
            run_c=lambda: c_module._aten_dispatch(
                op, _pair(torch_module, c_module, [float("nan"), 1.0], (2,), "float32")[1], 1.0
            ),
            note="NaN is not > anything, including a value smaller than the other element",
        )
    )
    cases.append(
        Case(
            name="gt(bool, [T,F] > 0) [bool compares as 0/1 against an int scalar]",
            op=op,
            run_torch=lambda: torch_call(_pair(torch_module, c_module, [1, 0], (2,), "bool")[0], 0),
            run_c=lambda: c_module._aten_dispatch(op, _pair(torch_module, c_module, [1, 0], (2,), "bool")[1], 0),
            note="True > 0 is True, False > 0 is False (measured)",
        )
    )
    return cases


def masked_select_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.masked_select.default"
    cases: list[Case] = []

    # 2-D self, 2-D bool mask, same shape -- the base case. Mask construction
    # follows `masked_fill__scalar_cases`'s pattern: `_C`'s `_tensor_from_flat`
    # takes an int 0/1 flat list with an explicit `dtype=c_module.bool`; torch
    # builds the mask straight from a python bool list.
    a_flat, a_shape = [1, 2, 3, 4, 5, 6], (2, 3)
    mask_flat = [True, False, True, False, True, False]
    for dtype_name in ["float64", "float32", "int64", "int32", "uint8"]:
        a_flat_typed = [float(v) for v in a_flat] if "float" in dtype_name else a_flat
        cases.append(
            Case(
                name=f"masked_select(dtype={dtype_name}, self=(2,3), mask=(2,3)) [checkerboard mask]",
                op=op,
                run_torch=lambda dtype_name=dtype_name, a=a_flat_typed: torch_call(
                    torch_module.tensor(a, dtype=dt.torch_dtype(torch_module, dtype_name)).reshape(list(a_shape)),
                    torch_module.tensor(mask_flat).reshape(list(a_shape)),
                ),
                run_c=lambda dtype_name=dtype_name, a=a_flat_typed: c_module._aten_dispatch(
                    op,
                    c_module._tensor_from_flat(a, list(a_shape), dtype=dt.c_dtype(c_module, dtype_name)),
                    c_module._tensor_from_flat([int(v) for v in mask_flat], list(a_shape), dtype=c_module.bool),
                ),
                note="same-shape mask, three True and three False -- a 1-D result of length 3",
            )
        )

    # Broadcasting mask: (N,1) against a (N,hidden) receiver -- the same
    # sentinel-mask shape `masked_fill__scalar_cases` documents for mixtral,
    # measured here to also broadcast (not refuse) under masked_select.
    b_flat, b_shape = [float(v) for v in range(1, 9)], (4, 2)
    bmask_flat = [True, False, True, False]
    cases.append(
        Case(
            name="masked_select(dtype=float32, mask (4,1) broadcasts into self (4,2))",
            op=op,
            run_torch=lambda: torch_call(
                torch_module.tensor(b_flat).reshape(list(b_shape)),
                torch_module.tensor(bmask_flat).reshape([4, 1]),
            ),
            run_c=lambda: c_module._aten_dispatch(
                op,
                c_module._tensor_from_flat(b_flat, list(b_shape), dtype=c_module.float32),
                c_module._tensor_from_flat([int(v) for v in bmask_flat], [4, 1], dtype=c_module.bool),
            ),
            note="mask broadcasts along the last dim (measured) -- rows 0 and 2 survive whole",
        )
    )

    # All-False: an empty result, not a refusal (measured). Shape and dtype
    # still matter -- an empty result is exactly the kind of thing a shim
    # could get right in dtype/shape and still return as the wrong rank.
    cases.append(
        Case(
            name="masked_select(dtype=int64, all-False mask) [empty result]",
            op=op,
            run_torch=lambda: torch_call(
                torch_module.tensor(a_flat, dtype=torch_module.int64).reshape(list(a_shape)),
                torch_module.zeros(a_shape, dtype=torch_module.bool),
            ),
            run_c=lambda: c_module._aten_dispatch(
                op,
                c_module._tensor_from_flat(a_flat, list(a_shape), dtype=c_module.int64),
                c_module._tensor_from_flat([0] * 6, list(a_shape), dtype=c_module.bool),
            ),
            note="torch gives a 1-D, 0-element int64 tensor -- not a refusal, and not 0-d (measured)",
        )
    )

    # All-True: the whole tensor, flattened.
    cases.append(
        Case(
            name="masked_select(dtype=int64, all-True mask) [whole tensor, flattened]",
            op=op,
            run_torch=lambda: torch_call(
                torch_module.tensor(a_flat, dtype=torch_module.int64).reshape(list(a_shape)),
                torch_module.ones(a_shape, dtype=torch_module.bool),
            ),
            run_c=lambda: c_module._aten_dispatch(
                op,
                c_module._tensor_from_flat(a_flat, list(a_shape), dtype=c_module.int64),
                c_module._tensor_from_flat([1] * 6, list(a_shape), dtype=c_module.bool),
            ),
            note="every element survives, in row-major flattened order",
        )
    )
    return cases


def min_default_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.min.default"
    cases: list[Case] = []
    # Mirrors `max_default_cases`' own scenarios exactly (same dtypes, same
    # shapes) -- the point is the same kernel-selection risk in the opposite
    # direction, not a different set of inputs.
    for dtype_name in _REDUCE_DTYPES:
        for flat, shape, note in [
            ([1, 5, 2, 9, 0, 3], (2, 3), "global min, flattened"),
            ([-5, -1, -9, -3], (2, 2), "all-negative values"),
            ([7], (1,), "single element"),
        ]:
            cases.append(_unary_case(torch_module, c_module, op, torch_call, dtype_name, flat, shape, note))
    # NaN propagates rather than being ignored (measured) -- torch does not
    # treat min as nan-skipping the way e.g. nanmin would.
    #
    # Walked through three positions rather than left at one. The single case
    # here had the NaN in the middle, which does exercise the fault, but the
    # rest of this family was audited in docs/TRIL.md §3 and the audit's rule
    # is that a NaN suite states its positions: a suite with only `at=0` cannot
    # fail, because element 0 seeds candle's accumulator and nothing displaces
    # it. Cheap insurance, and it makes the pattern uniform across the six ops
    # that now share the rule.
    nan = float("nan")
    for at, where in [(0, "first"), (1, "middle"), (3, "last")]:
        flat = [1.0, 5.0, 2.0, 9.0]
        flat[at] = nan
        for dtype_name in ["float64", "float32", "float16", "bfloat16"]:
            cases.append(
                _unary_case(
                    torch_module, c_module, op, torch_call, dtype_name, flat, (4,),
                    f"NaN in the {where} position propagates: min() of a tensor containing "
                    f"NaN is NaN (measured)",
                )
            )
    # No empty-tensor case: `max_default_cases` does not have one either --
    # measured, torch's `min()` raises on an empty input ("Expected reduction
    # dim to be specified for input.numel() == 0"), so it is out of scope for
    # the same reason that one is.
    return cases


def unbind_int_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.unbind.int"
    cases: list[Case] = []

    for dtype_name in ["float32", "int64"]:
        a_t, a_c = pair_from_flat(torch_module, c_module, list(range(6)), (2, 3), dtype_name)
        cases.append(
            Case(
                name=f"unbind(dtype={dtype_name}, shape=(2,3), dim=0) [two rows]",
                op=op,
                run_torch=lambda a_t=a_t: torch_call(a_t, 0),
                run_c=lambda a_c=a_c: c_module._aten_dispatch(op, a_c, 0),
                value_check=_chunk_list_check,
                note="dim=0 on a 2-D tensor -- a list of two 1-D tensors, see _chunk_list_check",
            )
        )

    b_t, b_c = pair_from_flat(torch_module, c_module, list(range(6)), (2, 3), "float32")
    cases.append(
        Case(
            name="unbind(dtype=float32, shape=(2,3), dim=1) [non-zero dim, three columns]",
            op=op,
            run_torch=lambda: torch_call(b_t, 1),
            run_c=lambda: c_module._aten_dispatch(op, b_c, 1),
            value_check=_chunk_list_check,
            note="dim=1 -- a list of three 1-D tensors, one per column",
        )
    )
    cases.append(
        Case(
            name="unbind(dtype=float32, shape=(2,3), dim=-1) [negative dim]",
            op=op,
            run_torch=lambda: torch_call(b_t, -1),
            run_c=lambda: c_module._aten_dispatch(op, b_c, -1),
            value_check=_chunk_list_check,
            note="dim=-1 addresses the same axis as dim=1 (measured identical result)",
        )
    )

    c_t, c_c = pair_from_flat(torch_module, c_module, [1, 2, 3], (3,), "float32")
    cases.append(
        Case(
            name="unbind(dtype=float32, shape=(3,), dim=0) [1-D self -- 0-d results]",
            op=op,
            run_torch=lambda: torch_call(c_t, 0),
            run_c=lambda: c_module._aten_dispatch(op, c_c, 0),
            value_check=_chunk_list_check,
            note="a 1-D input unbinds into a list of 0-d tensors (measured)",
        )
    )

    d_t, d_c = pair_from_flat(torch_module, c_module, list(range(24)), (2, 3, 4), "float32")
    cases.append(
        Case(
            name="unbind(dtype=float32, shape=(2,3,4), dim=1) [3-D self]",
            op=op,
            run_torch=lambda: torch_call(d_t, 1),
            run_c=lambda: c_module._aten_dispatch(op, d_c, 1),
            value_check=_chunk_list_check,
            note="a list of three (2,4) tensors -- the unbound dim disappears from every chunk",
        )
    )

    e_t, e_c = pair_from_flat(torch_module, c_module, [], (0, 3), "float32")
    cases.append(
        Case(
            name="unbind(dtype=float32, shape=(0,3), dim=0) [extent 0 along the unbind dim]",
            op=op,
            run_torch=lambda: torch_call(e_t, 0),
            run_c=lambda: c_module._aten_dispatch(op, e_c, 0),
            value_check=_chunk_list_check,
            note="zero rows to unbind -- an empty list, not an error (measured)",
        )
    )
    return cases


# --- aten._grouped_mm.default ----------------------------------------------
#
# The mixture-of-experts GEMM, and the operator docs/OPS4.md §13.3 named as the
# one thing keeping Mixtral off the "zero missing operators" list. See
# docs/GROUPED_MM.md for the schema, the four layouts, and the measurements
# behind every refusal below.
#
# Three dtypes, because upstream's CPU kernel takes exactly three (f32, bf16,
# f16) and the meta function's bf16-only rule is NOT the CPU contract --
# reading the meta function as the specification would have refused the dtype
# Mixtral actually calls this with.
_GROUPED_MM_DTYPES = ["float32", "bfloat16", "float16"]

# 16 / itemsize, in elements. `_grouped_mm`'s CPU kernel refuses operands whose
# last-two-dimension strides are not a multiple of 16 bytes, so every "match"
# case below has to be shaped to satisfy it and the shapes are not free.
# 16 and 8 clear both (16 % 8 == 0, 8 % 8 == 0), which is why they recur.
_GROUPED_MM_M, _GROUPED_MM_K, _GROUPED_MM_N = 24, 16, 8


def _grouped_offs(torch_module, c_module, values):
    return pair_from_flat(torch_module, c_module, values, (len(values),), "int32")


def _grouped_mm_case(
    torch_module,
    c_module,
    torch_call,
    name,
    a_pair,
    b_pair,
    offs,
    dtype_name,
    k,
    expect="match",
    note="",
    kwargs_t=None,
    kwargs_c=None,
    value_check=None,
):
    op = "aten._grouped_mm.default"
    a_t, a_c = a_pair
    b_t, b_c = b_pair
    o_t, o_c = offs if offs is not None else (None, None)
    kwargs_t = kwargs_t or {}
    kwargs_c = kwargs_c or {}
    if value_check is None and expect == "match":
        value_check = _gemm_scale_check(dtype_name, k)
    return Case(
        name=f"_grouped_mm(dtype={dtype_name}) [{name}]",
        op=op,
        run_torch=lambda: torch_call(a_t, b_t, o_t, **kwargs_t),
        run_c=lambda: c_module._aten_dispatch(op, a_c, b_c, o_c, **kwargs_c),
        expect=expect,
        note=note,
        value_check=value_check,
    )


def _grouped_short_offs_case(torch_module, c_module, torch_call, a_pair, b_pair, offs, dtype_name, k, written):
    """`offs[-1] < M` leaves the tail of the output **unwritten** -- upstream
    returns whatever `torch.empty` gave it, and `transformers` masks those rows
    itself rather than reading them (`integrations/moe.py`, the expert-parallel
    sentinel comment). What this case pins is that a short `offs` does not
    disturb the rows it *does* write, which is a real off-by-one trap in the
    offset walk and one no full-length `offs` case can reach.

    The tail is dropped **in the case, with `aten.slice.Tensor`, not in a
    comparator.** A comparator that ignored the last rows would be blind to the
    harness's own `value-last` fault injection, and `--self-test` says so --
    correctly, because that blindness would then apply to every case using it.
    Slicing on the way out instead keeps `_gemm_scale_check`, whose fault
    profile is already established, as the thing doing the comparing.
    """
    op = "aten._grouped_mm.default"
    a_t, a_c = a_pair
    b_t, b_c = b_pair
    o_t, o_c = offs

    def run_torch():
        full = torch_call(a_t, b_t, o_t)
        return torch_module.ops.aten.slice.Tensor(full, 0, 0, written)

    def run_c():
        full = c_module._aten_dispatch(op, a_c, b_c, o_c)
        return c_module._aten_dispatch("aten.slice.Tensor", full, 0, 0, written)

    return Case(
        name=(
            f"_grouped_mm(dtype={dtype_name}) [2Dx3D, offs[-1]={written} < M="
            f"{_GROUPED_MM_M} -- tail unwritten, compared over rows [0,{written}) only]"
        ),
        op=op,
        run_torch=run_torch,
        run_c=run_c,
        value_check=_gemm_scale_check(dtype_name, k),
        note=(
            "transformers relies on the unwritten tail for expert-parallel sentinel rows "
            "and masks it itself; there is no correct value there to compare, so the case "
            "slices it off rather than teaching a comparator to look away"
        ),
    )


def grouped_mm_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten._grouped_mm.default"
    m, k, n = _GROUPED_MM_M, _GROUPED_MM_K, _GROUPED_MM_N
    cases: list[Case] = []

    for dtype_name in _GROUPED_MM_DTYPES:
        a2 = pair_from_flat(torch_module, c_module, _gemm_lcg(m * k, 8101), (m, k), dtype_name)
        b3 = pair_from_flat(torch_module, c_module, _gemm_lcg(3 * k * n, 8102), (3, k, n), dtype_name)

        # -- 2-D x 3-D, the layout Mixtral calls. Group sizes are deliberately
        # UNEVEN: equal-sized groups are computed correctly by an offset walk
        # that is off by one at every boundary, because every boundary is then
        # a multiple of the same stride. 5 / 4 / 15 shares no factor.
        cases.append(
            _grouped_mm_case(
                torch_module, c_module, torch_call,
                "2Dx3D, groups 5/4/15 -- uneven on purpose", a2, b3,
                _grouped_offs(torch_module, c_module, [5, 9, 24]), dtype_name, k,
                note="equal-sized groups hide an off-by-one in the offset walk; these do not",
            )
        )
        # An empty group in each of the three positions. `offs` is a cumulative
        # end index, so a repeated value means "this expert got no tokens" --
        # which is the common case in a real MoE layer with more experts than
        # a short prompt has tokens, and it is what Mixtral's own trace shows
        # (offs [5,10,10,16], group 2 empty).
        for label, values in [
            ("empty FIRST group", [0, 9, 24]),
            ("empty MIDDLE group", [5, 5, 24]),
            ("empty LAST group", [5, 24, 24]),
        ]:
            cases.append(
                _grouped_mm_case(
                    torch_module, c_module, torch_call,
                    f"2Dx3D, {label}", a2, b3,
                    _grouped_offs(torch_module, c_module, values), dtype_name, k,
                    note="a repeated offset is an expert that routed no tokens; measured in Mixtral's own trace",
                )
            )
        # One group covering everything -- the degenerate case where this op is
        # just `mm`, and the one where a walk that never advances still passes.
        b1 = pair_from_flat(torch_module, c_module, _gemm_lcg(k * n, 8103), (1, k, n), dtype_name)
        cases.append(
            _grouped_mm_case(
                torch_module, c_module, torch_call,
                "2Dx3D, a SINGLE group spanning every row", a2, b1,
                _grouped_offs(torch_module, c_module, [24]), dtype_name, k,
                note="G=1: the answer is plain mm, and the offset walk must still produce it",
            )
        )
        # Offsets that go backwards. Upstream does not validate monotonicity;
        # it is a sequential write loop and a later group overwrites an earlier
        # one. Nonsense input, but a *defined* answer, and a cat-of-blocks
        # implementation gets it wrong.
        cases.append(
            _grouped_mm_case(
                torch_module, c_module, torch_call,
                "2Dx3D, offs [9,5,24] -- DECREASING, later group overwrites", a2, b3,
                _grouped_offs(torch_module, c_module, [9, 5, 24]), dtype_name, k,
                note="upstream never checks that offsets increase; the write loop's overwrite is the answer",
            )
        )
        # A short `offs`: the tail is upstream-uninitialised, so the case
        # slices it off. See `_grouped_short_offs_case`.
        cases.append(
            _grouped_short_offs_case(
                torch_module, c_module, torch_call, a2, b3,
                _grouped_offs(torch_module, c_module, [5, 9, 20]), dtype_name, k, 20,
            )
        )

        # -- 2-D x 3-D with a TRANSPOSED right operand. This is not a variation
        # for its own sake: `transformers`' `_grouped_linear` passes
        # `weight.transpose(-2, -1)` on every call unless the checkpoint is
        # already transposed, so a non-contiguous `mat2` is Mixtral's normal
        # case rather than its exotic one.
        wbase_t, wbase_c = pair_from_flat(
            torch_module, c_module, _gemm_lcg(3 * n * k, 8104), (3, n, k), dtype_name
        )
        wt_t = wbase_t.transpose(-2, -1)
        wt_c = c_module._aten_dispatch("aten.transpose.int", wbase_c, -2, -1)
        cases.append(
            _grouped_mm_case(
                torch_module, c_module, torch_call,
                "2Dx3D, mat2 a TRANSPOSED view -- transformers' actual weight layout",
                a2, (wt_t, wt_c),
                _grouped_offs(torch_module, c_module, [5, 9, 24]), dtype_name, k,
                note="_grouped_linear passes weight.transpose(-2,-1); the kernel must consume the view, not refuse it",
            )
        )

        # -- 3-D x 2-D: `offs` partitions the *columns* of the right operand,
        # and the output stays 2-D. A kernel that only ever learned the 2Dx3D
        # layout produces the wrong rank here.
        a3 = pair_from_flat(
            torch_module, c_module, _gemm_lcg(3 * _GROUPED_MM_N * k, 8105), (3, n, k), dtype_name
        )
        b2wide = pair_from_flat(
            torch_module, c_module, _gemm_lcg(k * m, 8106), (k, m), dtype_name
        )
        cases.append(
            _grouped_mm_case(
                torch_module, c_module, torch_call,
                "3Dx2D, offs over mat2's COLUMNS, uneven 5/4/15", a3, b2wide,
                _grouped_offs(torch_module, c_module, [5, 9, 24]), dtype_name, k,
                note="a different axis is partitioned and the output is 2-D, not 3-D",
            )
        )

        # -- 2-D x 2-D: `offs` partitions the CONTRACTION, so the groups do not
        # share an output -- each is its own matrix and they stack to (G,M,N).
        # This is the layout whose output rank differs from its inputs'.
        a2k = pair_from_flat(torch_module, c_module, _gemm_lcg(n * m, 8107), (n, m), dtype_name)
        b2k = pair_from_flat(torch_module, c_module, _gemm_lcg(m * n, 8108), (m, n), dtype_name)
        for label, values, depth in [
            ("uneven 8/8/8 split of K=24", [8, 16, 24], 8),
            ("uneven 5/4/15 split of K=24", [5, 9, 24], 15),
            ("an EMPTY contraction group -> a zero matrix", [0, 9, 24], 15),
        ]:
            cases.append(
                _grouped_mm_case(
                    torch_module, c_module, torch_call,
                    f"2Dx2D, offs over the CONTRACTION, {label}", a2k, b2k,
                    _grouped_offs(torch_module, c_module, values), dtype_name, depth,
                    note="output is (G,M,N) -- rank goes UP, unlike every other layout",
                )
            )

        # -- 3-D x 3-D: no offsets at all; upstream's meta function calls this
        # "regular bmm" and the CPU kernel agrees.
        a3b = pair_from_flat(
            torch_module, c_module, _gemm_lcg(3 * n * k, 8109), (3, n, k), dtype_name
        )
        b3b = pair_from_flat(
            torch_module, c_module, _gemm_lcg(3 * k * n, 8110), (3, k, n), dtype_name
        )
        cases.append(
            _grouped_mm_case(
                torch_module, c_module, torch_call,
                "3Dx3D, NO offsets -- plain bmm", a3b, b3b, None, dtype_name, k,
                note="both operands 3-D: offsets are forbidden and this degenerates to bmm",
            )
        )

        # -- `out_dtype` at its only accepted value. The schema takes a
        # `ScalarType?` but the kernel accepts only the input dtype, so the
        # identity is the whole of the supported range and is worth pinning:
        # a kernel that ignored the argument entirely would also pass a
        # `None`-only battery.
        cases.append(
            _grouped_mm_case(
                torch_module, c_module, torch_call,
                f"2Dx3D, out_dtype={dtype_name} (the identity -- the only value upstream takes)",
                a2, b3, _grouped_offs(torch_module, c_module, [5, 9, 24]), dtype_name, k,
                kwargs_t={"out_dtype": dt.torch_dtype(torch_module, dtype_name)},
                kwargs_c={"out_dtype": dt.c_dtype(c_module, dtype_name)},
                note="out_dtype is in the schema; the only value that is not refused is mat_a's own",
            )
        )

        # -- Model-scale depth. The three dtypes accumulate differently
        # (float16 accumulates in float32 upstream, and a kernel that
        # accumulated in float16 is only visibly wrong once k is large), so the
        # depth here is doing the same job it does in `bmm_cases`' big case.
        big_k = 128
        big_a = pair_from_flat(
            torch_module, c_module, _gemm_lcg(64 * big_k, 8111), (64, big_k), dtype_name
        )
        big_b = pair_from_flat(
            torch_module, c_module, _gemm_lcg(4 * big_k * 32, 8112), (4, big_k, 32), dtype_name
        )
        cases.append(
            _grouped_mm_case(
                torch_module, c_module, torch_call,
                "2Dx3D model-scale, 4 experts x k=128, groups 7/25/1/31", big_a, big_b,
                _grouped_offs(torch_module, c_module, [7, 32, 33, 64]), dtype_name, big_k,
                note="depth enough for the accumulation dtype to show; float16 must accumulate in float32",
            )
        )

    # -- Refusals. Every message below is upstream's own; see
    # docs/GROUPED_MM.md §2.1 for the table they were measured into.
    f32_a = pair_from_flat(torch_module, c_module, _gemm_lcg(m * k, 8201), (m, k), "float32")
    f32_b3 = pair_from_flat(torch_module, c_module, _gemm_lcg(3 * k * n, 8202), (3, k, n), "float32")
    offs3 = _grouped_offs(torch_module, c_module, [5, 9, 24])

    # Dtypes outside {f32, bf16, f16}. float64 is the interesting one: candle
    # has a float64 matmul and mm/bmm/addmm all use it, so this is a case where
    # the shim has the capability and must decline to use it.
    for dtype_name, fill, why in [
        ("float64", 1.0, "candle HAS a float64 matmul and mm uses it; _grouped_mm's CPU kernel does not take it"),
        ("int64", 1, "no integer grouped GEMM upstream"),
        ("uint8", 1, "no integer grouped GEMM upstream"),
    ]:
        bad_a = pair_from_flat(torch_module, c_module, [fill] * (m * k), (m, k), dtype_name)
        bad_b = pair_from_flat(torch_module, c_module, [fill] * (3 * k * n), (3, k, n), dtype_name)
        cases.append(
            _grouped_mm_case(
                torch_module, c_module, torch_call,
                f"REFUSE dtype={dtype_name}", bad_a, bad_b, offs3, dtype_name, k,
                expect="both_error",
                note=f"torch: 'Expected mat_a to be Float32, BFloat16 or Float16 matrix, got ...'. {why}",
            )
        )

    f16_b3 = pair_from_flat(torch_module, c_module, _gemm_lcg(3 * k * n, 8203), (3, k, n), "float16")
    cases.append(
        _grouped_mm_case(
            torch_module, c_module, torch_call,
            "REFUSE float32 x float16 -- no promotion", f32_a, f16_b3, offs3, "float32", k,
            expect="both_error",
            note="torch: 'expected m1 and m2 to have the same dtype'; this op does not promote",
        )
    )

    # The 16-byte stride rule (docs/GROUPED_MM.md §2.2). Both directions:
    # an unaligned leading stride on the 2-D operand, and on the 3-D one.
    thin_a = pair_from_flat(torch_module, c_module, _gemm_lcg(8 * 3, 8204), (8, 3), "float32")
    thin_b = pair_from_flat(torch_module, c_module, _gemm_lcg(3 * 3 * 4, 8205), (3, 3, 4), "float32")
    offs_thin = _grouped_offs(torch_module, c_module, [2, 5, 8])
    cases.append(
        _grouped_mm_case(
            torch_module, c_module, torch_call,
            "REFUSE (8,3)x(3,3,4) float32 -- K=3 is not a multiple of 16 bytes",
            thin_a, thin_b, offs_thin, "float32", 3,
            expect="both_error",
            note=(
                "torch: 'strides should be multiple of 16 bytes'. candle would multiply these "
                "happily -- this refusal exists only because upstream's CPU kernel has it, and "
                "computing here would be silent divergence"
            ),
        )
    )
    wide_a = pair_from_flat(torch_module, c_module, _gemm_lcg(8 * 4, 8206), (8, 4), "float32")
    narrow_b = pair_from_flat(torch_module, c_module, _gemm_lcg(3 * 4 * 3, 8207), (3, 4, 3), "float32")
    cases.append(
        _grouped_mm_case(
            torch_module, c_module, torch_call,
            "REFUSE (8,4)x(3,4,3) float32 -- N=3 is not a multiple of 16 bytes",
            wide_a, narrow_b, offs_thin, "float32", 4,
            expect="both_error",
            note="the same rule applied to the right operand's inner stride",
        )
    )
    # bfloat16's alignment is 8 elements, not 4 -- so a shape that is fine in
    # float32 is refused in bfloat16. A single hardcoded alignment would pass
    # the float32 cases above and fail here.
    bf_a = pair_from_flat(torch_module, c_module, _gemm_lcg(8 * 4, 8208), (8, 4), "bfloat16")
    bf_b = pair_from_flat(torch_module, c_module, _gemm_lcg(3 * 4 * 4, 8209), (3, 4, 4), "bfloat16")
    cases.append(
        _grouped_mm_case(
            torch_module, c_module, torch_call,
            "REFUSE (8,4)x(3,4,4) bfloat16 -- 4 elements is 8 bytes, not 16",
            bf_a, bf_b, offs_thin, "bfloat16", 4,
            expect="both_error",
            note="alignment is 16/itemsize ELEMENTS; the identical float32 shape is accepted",
        )
    )

    # Offsets: dtype, rank, presence, length.
    offs64 = pair_from_flat(torch_module, c_module, [5, 9, 24], (3,), "int64")
    cases.append(
        _grouped_mm_case(
            torch_module, c_module, torch_call,
            "REFUSE offs int64 -- must be int32", f32_a, f32_b3, offs64, "float32", k,
            expect="both_error",
            note="torch: 'Offsets have to be int32'. transformers builds offs with cumsum(dtype=torch.int32) for this reason",
        )
    )
    offs2d = pair_from_flat(torch_module, c_module, [5, 9, 24], (3, 1), "int32")
    cases.append(
        _grouped_mm_case(
            torch_module, c_module, torch_call,
            "REFUSE offs 2-D", f32_a, f32_b3, offs2d, "float32", k,
            expect="both_error", note="torch: 'offs has to be 1D'",
        )
    )
    cases.append(
        _grouped_mm_case(
            torch_module, c_module, torch_call,
            "REFUSE 2Dx3D with NO offsets", f32_a, f32_b3, None, "float32", k,
            expect="both_error",
            note="torch: 'Have to provide offsets if there is a 2d matrix, or no offset if both matrices are 3d'",
        )
    )
    f32_a3 = pair_from_flat(torch_module, c_module, _gemm_lcg(3 * n * k, 8210), (3, n, k), "float32")
    cases.append(
        _grouped_mm_case(
            torch_module, c_module, torch_call,
            "REFUSE 3Dx3D WITH offsets", f32_a3, f32_b3, offs3, "float32", k,
            expect="both_error",
            note="the same message from the other side: two 3-D operands must NOT carry offsets",
        )
    )
    offs2 = _grouped_offs(torch_module, c_module, [9, 24])
    cases.append(
        _grouped_mm_case(
            torch_module, c_module, torch_call,
            "REFUSE offs length 2 against a batch of 3", f32_a, f32_b3, offs2, "float32", k,
            expect="both_error", note="torch: 'matrix batch sizes have to match'",
        )
    )

    # Shape agreement.
    deep_b = pair_from_flat(torch_module, c_module, _gemm_lcg(3 * m * n, 8211), (3, m, n), "float32")
    cases.append(
        _grouped_mm_case(
            torch_module, c_module, torch_call,
            "REFUSE contraction 16 vs 24", f32_a, deep_b, offs3, "float32", k,
            expect="both_error", note="torch: 'contraction dimension of mat_a and mat_b must match'",
        )
    )
    two_batch = pair_from_flat(torch_module, c_module, _gemm_lcg(2 * n * k, 8212), (2, n, k), "float32")
    cases.append(
        _grouped_mm_case(
            torch_module, c_module, torch_call,
            "REFUSE 3Dx3D batch 2 vs 3", two_batch, f32_b3, None, "float32", k,
            expect="both_error", note="torch: 'batched dimension has to match'",
        )
    )
    rank1 = pair_from_flat(torch_module, c_module, _gemm_lcg(k, 8213), (k,), "float32")
    cases.append(
        _grouped_mm_case(
            torch_module, c_module, torch_call,
            "REFUSE 1-D mat_a", rank1, f32_b3, offs3, "float32", k,
            expect="both_error", note="torch: 'mat_a has to be 2 or 3d'",
        )
    )
    rank4 = pair_from_flat(
        torch_module, c_module, _gemm_lcg(2 * 2 * k * n, 8214), (2, 2, k, n), "float32"
    )
    cases.append(
        _grouped_mm_case(
            torch_module, c_module, torch_call,
            "REFUSE 4-D mat_b", f32_a, rank4, offs3, "float32", k,
            expect="both_error", note="torch: 'mat_b has to be 2 or 3d'",
        )
    )

    # `bias` and a non-identity `out_dtype`: both are in the schema and neither
    # is implemented upstream. Refusing them is fidelity, not a capability gap
    # -- computing a bias here would answer a question torch declines to answer.
    bias = pair_from_flat(torch_module, c_module, [0.5] * n, (n,), "float32")
    cases.append(
        _grouped_mm_case(
            torch_module, c_module, torch_call,
            "REFUSE bias -- in the schema, unimplemented upstream", f32_a, f32_b3, offs3,
            "float32", k, expect="both_error",
            kwargs_t={"bias": bias[0]}, kwargs_c={"bias": bias[1]},
            note=(
                "torch: 'Bias not supported yet'. transformers works around it with a "
                "separate out.add_(bias), which is why _grouped_linear has that line"
            ),
        )
    )
    cases.append(
        _grouped_mm_case(
            torch_module, c_module, torch_call,
            "REFUSE out_dtype=float16 on float32 operands", f32_a, f32_b3, offs3, "float32", k,
            expect="both_error",
            kwargs_t={"out_dtype": dt.torch_dtype(torch_module, "float16")},
            kwargs_c={"out_dtype": dt.c_dtype(c_module, "float16")},
            note="torch: 'Grouped gemm output dtype must match `mat_a` dtype'",
        )
    )

    # The 2-D x 2-D layout is the one WITHOUT a contraction check, and that is
    # deliberate upstream: `offs` slices both operands with the same range, so
    # the extents outside it are never read. Adding the check the other layouts
    # have would refuse a call upstream computes -- so this case is a "match",
    # not a refusal, and it is here to keep it that way.
    mism_a = pair_from_flat(torch_module, c_module, _gemm_lcg(8 * 8, 8215), (8, 8), "float32")
    mism_b = pair_from_flat(torch_module, c_module, _gemm_lcg(4 * 4, 8216), (4, 4), "float32")
    cases.append(
        _grouped_mm_case(
            torch_module, c_module, torch_call,
            "2Dx2D with MISMATCHED K (8 vs 4) -- upstream computes, offs=[2,4]",
            mism_a, mism_b, _grouped_offs(torch_module, c_module, [2, 4]), "float32", 2,
            note="the 2Dx2D layout has no contraction check; only the offset range is read",
        )
    )

    return cases


# --- the Python-level member spellings (docs/GROUPED_MM.md §6.4) ------------
#
# Everything above calls `torch.ops.aten.<op>.<ov>` on the torch side and
# `_C._aten_dispatch(key, ...)` on the shim side. That compares the *kernels*,
# and it compared them correctly while `tensor.clamp_(...)`,
# `tensor >= 3`, `tensor.chunk(3)` and `tensor[idx] = v` all still raised
# `NotImplementedError` -- the seven names Mixtral needed had kernels the whole
# time and no way in. So the kernel cases could not have caught it, and a name
# with no case is a name nobody checks.
#
# These cases go through the *member* on both sides. `run_torch` calls
# `t.clamp_(max=3)` on a real `torch.Tensor`, `run_c` calls `t.clamp_(max=3)`
# on a `TensorBase`, and the harness diffs the two results exactly as before.
# Deleting a `methods.json` entry, or the `chunk`/`__setitem__` installers in
# `bootstrap.py`, fails these and nothing else.
#
# In-place members follow the same rule as every other in-place case here:
# a fresh operand pair per case, never shared, or an earlier mutation leaks
# into a later expectation.


def _free(module, name):
    """The free-function spelling `torch.<name>` on whichever side.

    `torch` hoists these onto the module; `_C` keeps them on
    `_C._VariableFunctions`, which is the object `torch/__init__.py` hoists
    *from*. Both are the same door onto `overloads.json`, and a case that
    reached for `_C.<name>` got an `AttributeError` -- which the harness
    correctly reported as a divergence, and which would just as correctly have
    made a `c_error` case "pass" for a reason having nothing to do with the
    overload under test.
    """
    if hasattr(module, name):
        return getattr(module, name)
    return getattr(module._VariableFunctions, name)


def _member_case(torch_module, c_module, op, name, dtype_name, pairs, call, expect="match",
                 note="", value_check=None) -> Case:
    """One case whose two sides are the same *member* call on the two tensor
    types. `pairs` is a list of `(torch_tensor, c_tensor)`; `call` is applied
    to whichever side's tensors, so the two sides cannot drift apart."""
    return Case(
        name=name,
        op=op,
        run_torch=lambda: call(torch_module, *[p[0] for p in pairs]),
        run_c=lambda: call(c_module, *[p[1] for p in pairs]),
        expect=expect,
        note=note,
        value_check=value_check,
    )


def _chunk_tuple_check(t_res, c_res) -> tuple[bool, str]:
    """`Tensor.chunk` returns a `tuple` upstream (`THPVariable_chunk`), while
    `torch.ops.aten.split.Tensor` returns a `list`. The container type is part
    of the answer -- `t.chunk(2) + (x,)` works and `list + tuple` does not --
    so it is checked before the chunks are."""
    for label, res in (("torch", t_res), ("c", c_res)):
        if not isinstance(res, tuple):
            return False, f"{label} side returned {type(res).__name__}, not tuple"
    return _chunk_list_check(t_res, c_res)


def _ge_member_cases(torch_module, c_module) -> list[Case]:
    op = "aten.ge.Scalar"
    cases: list[Case] = []
    # Three spellings of one kernel. `__ge__` is the one that was missing;
    # `ge` and the `>=` operator are what a caller actually writes.
    for spelling, call in (
        ("x.__ge__(3)", lambda m, a: a.__ge__(3)),
        ("x.ge(3)", lambda m, a: a.ge(3)),
        ("x >= 3", lambda m, a: a >= 3),
    ):
        for dtype_name in ["float32", "int64", "int32"]:
            pair = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (2, 2), dtype_name)
            cases.append(
                _member_case(
                    torch_module, c_module, op,
                    f"member {spelling} (dtype={dtype_name})", dtype_name, [pair], call,
                    note="mixtral's sentinel_mask = expert_ids_g >= num_experts, through "
                         "the member rather than the dispatch key",
                )
            )
    # NaN is not >= anything, including itself -- the same fact the kernel
    # case asserts, re-asserted on the path a caller takes.
    pair = pair_from_flat(torch_module, c_module, [float("nan"), 1.0], (2,), "float32")
    cases.append(
        _member_case(
            torch_module, c_module, op,
            "member x >= 1.0 with NaN (dtype=float32)", "float32", [pair],
            lambda m, a: a >= 1.0,
            note="every comparison against NaN is false, including through __ge__",
        )
    )
    return cases


def _ge_tensor_member_cases(torch_module, c_module) -> list[Case]:
    """`x >= tensor`, the spelling that resolved and then refused.

    `_ge_member_cases` above goes through `ge.Scalar` because its right-hand
    side is a Python number. These go through `ge.Tensor`, which is the half
    that had no kernel: `methods.json` listed both schema strings, so the
    member bound, and `_aten_dispatch` then raised `NotImplementedError` on
    the key. Deleting the `aten.ge.Tensor` arm in `aten.rs` fails these and
    the door-level cases above; deleting the `methods.json` entry fails only
    these."""
    op = "aten.ge.Tensor"
    cases: list[Case] = []
    for spelling, call in (
        ("x.__ge__(y)", lambda m, a, b: a.__ge__(b)),
        ("x.ge(y)", lambda m, a, b: a.ge(b)),
        ("x >= y", lambda m, a, b: a >= b),
    ):
        for dtype_name in ["float32", "int64", "int32"]:
            a = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (2, 2), dtype_name)
            b = pair_from_flat(torch_module, c_module, [1, 5, 3, 0], (2, 2), dtype_name)
            cases.append(
                _member_case(
                    torch_module, c_module, op,
                    f"member {spelling} (dtype={dtype_name})", dtype_name, [a, b], call,
                    note="mixed equal/greater/less in one call, so >= is separated from "
                         "both > and ==, through the member rather than the dispatch key",
                )
            )
    # 0-d right-hand side: a tensor, so still `ge.Tensor` and not `ge.Scalar`.
    a = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (2, 2), "int64")
    b = pair_from_flat(torch_module, c_module, [3], (), "int64")
    cases.append(
        _member_case(
            torch_module, c_module, op,
            "member x >= 0-d tensor (dtype=int64) [broadcast, and still the Tensor overload]",
            "int64", [a, b], lambda m, x, y: x >= y,
            note="a 0-d tensor on the right picks ge.Tensor, not ge.Scalar -- the two "
                 "overloads are told apart by the argument's type, not by its rank",
        )
    )
    # NaN through the member, matching the door-level case above.
    a = pair_from_flat(torch_module, c_module, [float("nan"), 1.0], (2,), "float32")
    b = pair_from_flat(torch_module, c_module, [float("nan"), 1.0], (2,), "float32")
    cases.append(
        _member_case(
            torch_module, c_module, op,
            "member x >= y with NaN on both sides (dtype=float32)", "float32", [a, b],
            lambda m, x, y: x >= y,
            note="nan >= nan is False even though the two sides hold the same bits; "
                 "1.0 >= 1.0 in the same call is True, so this is not a blanket False",
        )
    )
    return cases


def _div__member_cases(torch_module, c_module) -> list[Case]:
    op = "aten.div_.Tensor"
    cases: list[Case] = []
    # `div_` and `__idiv__` reach the same kernel. `torch/_tensor.py:1115`
    # spells `Tensor.__itruediv__` as `_C.TensorBase.__idiv__`, which is why
    # `x /= y` needs the second one and not just the first.
    for spelling, call in (
        ("x.div_(y)", lambda m, a, b: a.div_(b)),
        ("x.__idiv__(y)", lambda m, a, b: a.__idiv__(b)),
    ):
        for dtype_name in ["float64", "float32", "float16", "bfloat16"]:
            a_pair = pair_from_flat(torch_module, c_module, [1.0, 2.0, 3.0, 4.0, 5.0, 6.0], (3, 2), dtype_name)
            b_pair = pair_from_flat(torch_module, c_module, [2.0, 4.0, 5.0], (3, 1), dtype_name)
            cases.append(
                _member_case(
                    torch_module, c_module, op,
                    f"member {spelling} (dtype={dtype_name}, other (3,1) broadcasts)",
                    dtype_name, [a_pair, b_pair], call,
                    note="mixtral: top_k_weights /= top_k_weights.sum(-1, keepdim=True)",
                )
            )
    # Refused on both sides: true division cannot write back into an integer
    # receiver. The member has to refuse it too, not silently truncate.
    a_pair = pair_from_flat(torch_module, c_module, [4, 8], (2,), "int64")
    b_pair = pair_from_flat(torch_module, c_module, [2, 4], (2,), "int64")
    cases.append(
        _member_case(
            torch_module, c_module, op,
            "member x.div_(y) (dtype=int64) [refused on both sides]", "int64",
            [a_pair, b_pair], lambda m, a, b: a.div_(b), expect="both_error",
            note="result type Float can't be cast to the desired output type Long",
        )
    )
    return cases


def _clamp__member_cases(torch_module, c_module) -> list[Case]:
    op = "aten.clamp_.default"
    cases: list[Case] = []
    for dtype_name in ["int64", "int32", "float32", "float64"]:
        pair = pair_from_flat(torch_module, c_module, [1, 5, 10, -3], (4,), dtype_name)
        cases.append(
            _member_case(
                torch_module, c_module, op,
                f"member x.clamp_(max=3) (dtype={dtype_name})", dtype_name, [pair],
                lambda m, a: a.clamp_(max=3),
                note="mixtral's exact call shape: max only, min absent, by keyword",
            )
        )
    pair = pair_from_flat(torch_module, c_module, [1, 5, 10, -3], (4,), "float32")
    cases.append(
        _member_case(
            torch_module, c_module, op,
            "member x.clamp_(2, 8) (dtype=float32, both bounds positional)", "float32",
            [pair], lambda m, a: a.clamp_(2, 8),
            note="positional min/max bind the same overload the keyword form does",
        )
    )
    # Both bounds absent. Upstream raises RuntimeError from the kernel; the
    # shim resolves to `clamp_.Tensor` (the `.pyi` lists the Tensor overload
    # first and `None` binds it) and refuses by name because that overload has
    # no kernel. Different message, same refusal -- `both_error` is the
    # honest expectation, and it is here so that neither side starts
    # *computing* a no-op.
    pair = pair_from_flat(torch_module, c_module, [1.0, 2.0, 3.0], (3,), "float32")
    cases.append(
        _member_case(
            torch_module, c_module, op,
            "member x.clamp_() with no bounds [refused, NOT a no-op]", "float32",
            [pair], lambda m, a: a.clamp_(), expect="both_error",
            note="torch: \"At least one of 'min' or 'max' must not be None\"; shim: "
                 "resolves clamp_.Tensor, which has no kernel",
        )
    )
    return cases


def _masked_fill__member_cases(torch_module, c_module) -> list[Case]:
    op = "aten.masked_fill_.Scalar"
    cases: list[Case] = []
    for dtype_name in ["float32", "float64", "int64"]:
        pair = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (4,), dtype_name)
        mask = pair_from_flat(torch_module, c_module, [True, False, True, False], (4,), "bool")
        cases.append(
            _member_case(
                torch_module, c_module, op,
                f"member x.masked_fill_(mask, 0) (dtype={dtype_name})", dtype_name,
                [pair, mask], lambda m, a, b: a.masked_fill_(b, 0),
                note="mixtral's pre- and post-masks, through the member",
            )
        )
    # A large negative fill is the sentinel-masking shape mixtral uses, and
    # the value most likely to expose a dtype-narrowing bug.
    pair = pair_from_flat(torch_module, c_module, [1.0, 2.0, 3.0, 4.0], (2, 2), "float32")
    mask = pair_from_flat(torch_module, c_module, [True, False, False, True], (2, 2), "bool")
    cases.append(
        _member_case(
            torch_module, c_module, op,
            "member x.masked_fill_(mask, -1e30) (dtype=float32) [sentinel masking]",
            "float32", [pair, mask], lambda m, a, b: a.masked_fill_(b, -1e30),
            note="the large-negative fill an attention mask writes",
        )
    )
    return cases


def _chunk_member_cases(torch_module, c_module) -> list[Case]:
    """`Tensor.chunk` is `CompositeImplicitAutograd`: it lowers to
    `split.Tensor`, or to `split_with_sizes` when the dimension is empty. Both
    kernels were already here; the composition was not. Every case below is a
    place where "divide the extent by `chunks`" gives the wrong answer, which
    is why the composition is transcribed from upstream rather than guessed."""
    cases: list[Case] = []
    for dtype_name in ["float32", "int64"]:
        for chunks, note in (
            (3, "10 into 3 -- (4,4,2), NOT (3,3,3,1): the size is rounded UP"),
            (4, "10 into 4 -- (3,3,3,1)"),
            (5, "10 into 5 -- exact"),
            (1, "10 into 1 -- one whole chunk"),
            (10, "10 into 10 -- ten singletons"),
        ):
            pair = pair_from_flat(torch_module, c_module, list(range(10)), (10,), dtype_name)
            cases.append(
                _member_case(
                    torch_module, c_module, "aten.split.Tensor",
                    f"member x.chunk({chunks}) (dtype={dtype_name}, extent 10)", dtype_name,
                    [pair], lambda m, a, chunks=chunks: a.chunk(chunks),
                    value_check=_chunk_tuple_check, note=note,
                )
            )
    # `chunks` is an upper bound, not a promise: 3 elements into 7 chunks
    # gives THREE chunks, because the size rounds up to 1.
    pair = pair_from_flat(torch_module, c_module, [0, 1, 2], (3,), "int64")
    cases.append(
        _member_case(
            torch_module, c_module, "aten.split.Tensor",
            "member x.chunk(7) on extent 3 [three chunks come back, not seven]",
            "int64", [pair], lambda m, a: a.chunk(7),
            value_check=_chunk_tuple_check,
            note="chunks is an upper bound; ceil(3/7) == 1 so split_size 1 gives three",
        )
    )
    # A non-zero dim, and a negative one.
    for dim, note in ((1, "chunk on dim 1"), (-1, "chunk on a negative dim")):
        pair = pair_from_flat(torch_module, c_module, list(range(12)), (3, 4), "float32")
        cases.append(
            _member_case(
                torch_module, c_module, "aten.split.Tensor",
                f"member x.chunk(3, {dim}) on (3,4)", "float32", [pair],
                lambda m, a, dim=dim: a.chunk(3, dim),
                value_check=_chunk_tuple_check, note=note,
            )
        )
    # The zero-extent branch, which is the only one that goes through
    # `split_with_sizes` and the only one that returns exactly `chunks`.
    pair = pair_from_flat(torch_module, c_module, [], (0,), "float32")
    cases.append(
        _member_case(
            torch_module, c_module, "aten.split_with_sizes.default",
            "member x.chunk(3) on an EMPTY dim [three empty chunks, not one]",
            "float32", [pair], lambda m, a: a.chunk(3),
            value_check=_chunk_tuple_check,
            note="split_size is 0 here, and `split` would discard the chunk count -- "
                 "upstream branches to split_with_sizes for exactly this case",
        )
    )
    # Refusals, both of them upstream's own checks.
    pair = pair_from_flat(torch_module, c_module, list(range(10)), (10,), "float32")
    cases.append(
        _member_case(
            torch_module, c_module, "aten.split.Tensor",
            "member x.chunk(0) [refused]", "float32", [pair],
            lambda m, a: a.chunk(0), expect="both_error",
            note="torch: 'chunk expects `chunks` to be greater than 0, got: 0'",
        )
    )
    pair = pair_from_flat(torch_module, c_module, [1.0], (), "float32")
    cases.append(
        _member_case(
            torch_module, c_module, "aten.split.Tensor",
            "member x.chunk(3) on a 0-d tensor [refused]", "float32", [pair],
            lambda m, a: a.chunk(3), expect="both_error",
            note="torch: 'chunk expects at least a 1-dimensional tensor'",
        )
    )
    return cases


def _view_write_cases(torch_module, c_module) -> list[Case]:
    """**Every case here throws the in-place op's return value away and
    compares the BASE.**

    That is the entire point of the builder and it is not a stylistic
    preference. Every in-place op returns `self`, so a case that compares the
    return value passes just as well against a kernel that computed into a
    fresh buffer and handed it back -- which is exactly what this shim did
    until docs/VIEWS.md §6. The whole suite was 3037 cases green while no
    in-place write was visible through any view. A case can only fail that way
    if it reads a name the op never returned.

    So each case: builds a base, narrows a *view* of it, writes through the
    view, and returns the base. Upstream runs the identical sequence, so the
    expectation is measured rather than asserted.

    The views are chosen for what they exercise in `tensor.rs::write_strided`:

      * `select.int(base, 1, k)` is **non-contiguous** -- stride `ncols`, so it
        takes the odometer branch. A shim that only handled contiguous
        destinations would pass the whole rest of the suite.
      * `t.default(base)` is non-contiguous in both axes.
      * `select.int(base, 0, k)` and `slice.Tensor(base, 0, i, j, 1)` are
        contiguous *with a non-zero start offset*, which is the other half a
        naive `dst[..numel]` write would get wrong.
      * `detach(base)` is the whole tensor, offset 0 -- the case that passes
        even against `replace_with`... except that `replace_with` swaps a
        *different wrapper*, so it fails there too.
    """
    A = torch_module.ops.aten

    def t_call(op, *args):
        name, over = op[len("aten."):].rsplit(".", 1)
        return getattr(getattr(A, name), over)(*args)

    def c_call(op, *args):
        return c_module._aten_dispatch(op, *args)

    cases: list[Case] = []

    def add(op, name, note, base_flat, base_shape, dtype_name, body, expect="match"):
        """`body(call, base)` narrows and writes; the base is what is compared."""
        def side(call, module_flat_builder):
            base = module_flat_builder()
            body(call, base)
            return base
        t_build = lambda: torch_module.tensor(
            list(base_flat), dtype=dt.torch_dtype(torch_module, dtype_name)
        ).reshape(list(base_shape))
        c_build = lambda: c_module._tensor_from_flat(
            list(base_flat), list(base_shape), dtype=dt.c_dtype(c_module, dtype_name)
        )
        cases.append(
            Case(
                name=name,
                op=op,
                run_torch=lambda: side(t_call, t_build),
                run_c=lambda: side(c_call, c_build),
                expect=expect,
                note=note,
            )
        )

    grid = [float(v) for v in range(1, 13)]          # 1..12
    signed = [float(v) for v in range(-6, 6)]        # -6..5

    # --- fill_.Scalar: the two view shapes, plus the whole-tensor alias -----
    add("aten.fill_.Scalar",
        "base after fill_(x[:,1], 7.0) [reads the BASE, not the view]",
        "select.int on dim 1 is a strided view; upstream's fill_ writes through it",
        grid, (3, 4), "float32",
        lambda call, base: call("aten.fill_.Scalar", call("aten.select.int", base, 1, 1), 7.0))
    add("aten.fill_.Scalar",
        "base after fill_(x[1], 7.0) [reads the BASE]",
        "select.int on dim 0 is contiguous with a non-zero start offset",
        grid, (3, 4), "float32",
        lambda call, base: call("aten.fill_.Scalar", call("aten.select.int", base, 0, 1), 7.0))
    add("aten.fill_.Scalar",
        "base after fill_(x.t(), 7.0) [reads the BASE]",
        "a transposed destination -- non-contiguous in both axes",
        grid, (3, 4), "float32",
        lambda call, base: call("aten.fill_.Scalar", call("aten.t.default", base), 7.0))
    add("aten.fill_.Scalar",
        "base after fill_(detach(x), 7.0) [reads the BASE]",
        "detach shares storage upstream and here; before write-through it did not "
        "share a wrapper, so the write was lost",
        grid, (3, 4), "float32",
        lambda call, base: call("aten.fill_.Scalar", call("aten.detach.default", base), 7.0))
    add("aten.fill_.Scalar",
        "base after fill_(x[1:3], 7.0) (dtype=int64) [reads the BASE]",
        "slice.Tensor at step 1 narrows; step > 1 does not, and is a recorded "
        "divergence in slice_cases",
        [float(v) for v in range(1, 13)], (3, 4), "int64",
        lambda call, base: call(
            "aten.fill_.Scalar", call("aten.slice.Tensor", base, 0, 1, 3, 1), 7))

    # --- zero_ -------------------------------------------------------------
    add("aten.zero_.default",
        "base after zero_(x[:,2]) [reads the BASE]",
        "zero_ is a separate overload from fill_(0) upstream and writes through too",
        grid, (3, 4), "float32",
        lambda call, base: call("aten.zero_.default", call("aten.select.int", base, 1, 2)))

    # --- copy_ -------------------------------------------------------------
    add("aten.copy_.default",
        "base after x[:,1].copy_(src) [reads the BASE]",
        "the column is filled from a (3,) source, positions 1, 5, 9 of the base",
        grid, (3, 4), "float32",
        lambda call, base: call(
            "aten.copy_.default", call("aten.select.int", base, 1, 1),
            call("aten.mul.Scalar", call("aten.select.int", base, 1, 0), 100.0)))
    add("aten.copy_.default",
        "base after x.t().copy_(x.t()*0) [reads the BASE]",
        "a transposed destination fed a transposed source",
        grid, (3, 4), "float32",
        lambda call, base: call(
            "aten.copy_.default", call("aten.t.default", base),
            call("aten.mul.Scalar", call("aten.t.default", base), 0.0)))
    # Two aliasing slices that do NOT overlap. Upstream permits this and so
    # does the shim, and it is the case `x[0:1] = x[1:2]` in `__setitem__`
    # reaches, so it has to keep working.
    add("aten.copy_.default",
        "base after x[0:1].copy_(x[1:2]) -- disjoint slices of one buffer",
        "measured: upstream permits a copy between two non-overlapping views of the "
        "same storage, and this is the shape `x[0:1] = x[1:2]` produces",
        grid, (3, 4), "float32",
        lambda call, base: call(
            "aten.copy_.default",
            call("aten.slice.Tensor", base, 0, 0, 1, 1),
            call("aten.slice.Tensor", base, 0, 1, 2, 1)))
    # ...and two that DO. **Recorded as a gap, not as agreement.** Upstream's
    # `assert_no_partial_overlap` raises "some elements of the input tensor and
    # the written-to tensor refer to a single memory location"; the shim reads
    # the source out into an owned buffer before it takes the destination's
    # lock (`tensor.rs::write_into`), so it computes a defined answer instead.
    #
    # Refusing to match would need upstream's `get_overlap_status`, which
    # compares the two storages' *data pointers* -- and candle's `storage()` is
    # `pub(crate)`. It is reachable at a price: an `InplaceOp1` that only reads
    # `CpuStorage::as_ptr` would recover the identity, at one extra write-lock
    # acquisition per in-place op with a tensor operand, on the hot path.
    # docs/VIEWS.md §6.5 has the argument for not paying it yet.
    add("aten.copy_.default",
        "x[0:2].copy_(x[1:3]) -- PARTIALLY overlapping, which upstream refuses",
        "known gap: upstream raises on a partial overlap between source and "
        "destination; this shim reads the source out first and computes "
        "[[5..8],[9..12],[9..12]] -- docs/VIEWS.md §6.5",
        grid, (3, 4), "float32",
        lambda call, base: call(
            "aten.copy_.default",
            call("aten.slice.Tensor", base, 0, 0, 2, 1),
            call("aten.slice.Tensor", base, 0, 1, 3, 1)),
        expect="torch_error")
    add("aten.copy_.default",
        "expand(x, ...).copy_(y) refuses -- destination addresses one element twice",
        "torch: 'unsupported operation: more than one element of the written-to tensor "
        "refers to a single memory location'. The source is an independent tensor on "
        "purpose: `copy_` short-circuits when the two sides are the same view, so an "
        "expanded source would make this case unable to fail",
        [1.0, 2.0], (1, 2), "float32",
        lambda call, base: call(
            "aten.copy_.default", call("aten.expand.default", base, [3, 2]),
            call("aten.mul.Scalar", call("aten.expand.default", base, [3, 2]), 0.0)),
        expect="both_error")

    # --- fill_.Tensor: refused on an expanded destination where .Scalar is not
    add("aten.fill_.Tensor",
        "expand(x, ...).fill_(0-d tensor) refuses where fill_.Scalar does not",
        "measured on torch 2.13.0: the Scalar overload writes an expanded tensor and "
        "the Tensor overload raises -- an asymmetry between two arms of one kernel",
        [1.0, 2.0], (1, 2), "float32",
        lambda call, base: call(
            "aten.fill_.Tensor", call("aten.expand.default", base, [3, 2]),
            call("aten.select.int", call("aten.select.int", base, 0, 0), 0, 0)),
        expect="both_error")

    # --- add_ / relu_ / clamp_ / div_ / masked_fill_ / index_put_ ----------
    add("aten.add_.Tensor",
        "base after x[:,1].add_(x[:,0]) [reads the BASE]",
        "arithmetic in place through a strided view",
        grid, (3, 4), "float32",
        lambda call, base: call(
            "aten.add_.Tensor", call("aten.select.int", base, 1, 1),
            call("aten.select.int", base, 1, 0)))
    add("aten.relu_.default",
        "base after x[:,1].relu_() [reads the BASE]",
        "the negatives in column 1 clamp to zero and the rest of the base is untouched",
        signed, (3, 4), "float32",
        lambda call, base: call(
            "aten.relu_.default", call("aten.select.int", base, 1, 1)))
    add("aten.clamp_.default",
        "base after x[:,1].clamp_(-1, 1) [reads the BASE]",
        "both bounds, through a strided view",
        signed, (3, 4), "float32",
        lambda call, base: call(
            "aten.clamp_.default", call("aten.select.int", base, 1, 1), -1.0, 1.0))
    add("aten.div_.Tensor",
        "base after x[:,1].div_(x[:,2]) [reads the BASE]",
        "true division in place through a strided view",
        grid, (3, 4), "float32",
        lambda call, base: call(
            "aten.div_.Tensor", call("aten.select.int", base, 1, 1),
            call("aten.select.int", base, 1, 2)))

    # --- the rest of the in-place arithmetic family (docs/ARCH20.md §8) -----
    #
    # Same shape as `add_.Tensor` above and here for the same reason: every one
    # of these returns `self`, so a case that read the return value would pass
    # just as well against a kernel that computed into a fresh buffer and
    # handed it back. These read the BASE.
    #
    # Three view shapes are used across the group on purpose -- `select.int` on
    # dim 1 (strided), `select.int` on dim 0 (contiguous at a non-zero offset)
    # and `t.default` (strided in both axes) -- so a write-through that handled
    # only the contiguous case cannot pass all of them.
    add("aten.sub_.Tensor",
        "base after x[:,1].sub_(x[:,0]) [reads the BASE]",
        "in-place subtract through a strided view",
        grid, (3, 4), "float32",
        lambda call, base: call(
            "aten.sub_.Tensor", call("aten.select.int", base, 1, 1),
            call("aten.select.int", base, 1, 0)))
    add("aten.mul_.Tensor",
        "base after x[1].mul_(x[0]) [reads the BASE]",
        "in-place multiply through a contiguous view at a non-zero offset",
        grid, (3, 4), "float32",
        lambda call, base: call(
            "aten.mul_.Tensor", call("aten.select.int", base, 0, 1),
            call("aten.select.int", base, 0, 0)))
    add("aten.add_.Scalar",
        "base after x[:,2].add_(10.0) [reads the BASE]",
        "the Scalar overload writes through the same layout the Tensor one does",
        grid, (3, 4), "float32",
        lambda call, base: call(
            "aten.add_.Scalar", call("aten.select.int", base, 1, 2), 10.0))
    add("aten.sub_.Scalar",
        "base after x[:,2].sub_(10.0) [reads the BASE]",
        "the Scalar overload of sub_, through a strided view",
        grid, (3, 4), "float32",
        lambda call, base: call(
            "aten.sub_.Scalar", call("aten.select.int", base, 1, 2), 10.0))
    add("aten.mul_.Scalar",
        "base after x.t().mul_(-1.0) [reads the BASE]",
        "a transposed destination -- non-contiguous in BOTH axes, so a write that "
        "walked row-major over the storage would scramble the base rather than "
        "negate it",
        grid, (3, 4), "float32",
        lambda call, base: call(
            "aten.mul_.Scalar", call("aten.t.default", base), -1.0))
    add("aten.neg_.default",
        "base after x[:,1].neg_() [reads the BASE]",
        "neg_ keeps the dtype and writes through a strided view; the other three "
        "columns of the base must come back untouched",
        signed, (3, 4), "float32",
        lambda call, base: call(
            "aten.neg_.default", call("aten.select.int", base, 1, 1)))
    add("aten.neg_.default",
        "base after x[1].neg_() (dtype=int64) [reads the BASE]",
        "the integral path -- candle's `neg` panics on i64, so this is the arm that "
        "goes through `0 - x`, checked through the base",
        [float(v) for v in range(-6, 6)], (3, 4), "int64",
        lambda call, base: call(
            "aten.neg_.default", call("aten.select.int", base, 0, 1)))
    add("aten.exp_.default",
        "base after x[:,0].exp_() [reads the BASE]",
        "exp_ through a strided view; upstream's exp_ is alias-preserving too",
        [v / 4.0 for v in range(-6, 6)], (3, 4), "float32",
        lambda call, base: call(
            "aten.exp_.default", call("aten.select.int", base, 1, 0)))

    # `masked_fill_` and `index_put_` need a mask/index operand, which
    # `_tensor_from_flat` will not build as bool directly -- same workaround
    # `masked_fill__scalar_cases` documents.
    def masked(call, base, mask):
        return call("aten.masked_fill_.Scalar", call("aten.select.int", base, 1, 1), mask, -1.0)

    t_mask = torch_module.tensor([True, False, True])
    c_mask = c_module._tensor_from_flat([1, 0, 1], [3], dtype=c_module.bool)
    cases.append(
        Case(
            name="base after x[:,1].masked_fill_(mask, -1.0) [reads the BASE]",
            op="aten.masked_fill_.Scalar",
            run_torch=lambda: (
                lambda b: (masked(t_call, b, t_mask), b)[1]
            )(torch_module.tensor(grid).reshape([3, 4])),
            run_c=lambda: (
                lambda b: (masked(c_call, b, c_mask), b)[1]
            )(c_module._tensor_from_flat(grid, [3, 4], dtype=c_module.float32)),
            note="a masked write through a strided view, read back through the base",
        )
    )

    t_idx = torch_module.tensor([0, 2])
    c_idx = c_module._tensor_from_flat([0, 2], [2], dtype=c_module.int64)

    def put(call, base, idx, values):
        return call(
            "aten.index_put_.default", call("aten.select.int", base, 1, 1),
            [idx], values, False)

    cases.append(
        Case(
            name="base after x[:,1].index_put_([0,2], v) [reads the BASE]",
            op="aten.index_put_.default",
            run_torch=lambda: (
                lambda b: (put(t_call, b, t_idx, torch_module.tensor([-1.0, -2.0])), b)[1]
            )(torch_module.tensor(grid).reshape([3, 4])),
            run_c=lambda: (
                lambda b: (
                    put(c_call, b, c_idx,
                        c_module._tensor_from_flat([-1.0, -2.0], [2], dtype=c_module.float32)),
                    b,
                )[1]
            )(c_module._tensor_from_flat(grid, [3, 4], dtype=c_module.float32)),
            note="index_put_ through a strided view, read back through the base",
        )
    )

    return cases


def _setitem_member_cases(torch_module, c_module) -> list[Case]:
    """`x[...] = v`. `__setitem__` is a walk over the index like
    `__getitem__`, and since docs/VIEWS.md §6 the basic-index half of that walk
    writes through the narrowing instead of refusing -- see the member's
    docstring in `bootstrap.py`.

    **Which of `copy_` and `fill_` a case lands on is a shape question, not a
    "number or tensor" question**, and the cases are grouped by op accordingly:
    upstream's `copy_to` uses `copy_` when the destination and the source have
    the same size, `fill_` when the source is 0-d, and a broadcast plus `copy_`
    otherwise. `x[0] = 3.0` is a `fill_` and `x[0,1] = 9.0` is a `copy_`, which
    is the pair that makes the rule visible.

    What still refuses is a slice with `step != 1` -- not because of the write
    but because `slice.Tensor` materialises above step 1, so there would be no
    view to write through. That refusal is pinned in
    `test_shim.py::test_setitem_writes_the_basic_index_through_to_the_base`,
    and the underlying divergence has its own `expect="diverge"` case in
    `slice_cases`."""

    def assigned(fn):
        # `__setitem__` returns None, so every case has to hand back the
        # mutated receiver for the pipeline to compare.
        def run(m, a, *rest):
            fn(a, *rest)
            return a
        return run

    cases: list[Case] = []
    op = "aten.index_put_.default"
    for dtype_name in ["float32", "int64", "int32"]:
        zeros = [0] * 5
        vals = [7, 8, 9]
        pair = pair_from_flat(torch_module, c_module, zeros, (5,), dtype_name)
        idx = pair_from_flat(torch_module, c_module, [0, 2, 4], (3,), "int64")
        values = pair_from_flat(torch_module, c_module, vals, (3,), dtype_name)
        cases.append(
            _member_case(
                torch_module, c_module, op,
                f"member x[idx] = values (dtype={dtype_name})", dtype_name,
                [pair, idx, values],
                assigned(lambda a, i, v: a.__setitem__(i, v)),
                note="mixtral's exact call shape: inv_perm[perm] = arange(perm.size(0)), "
                     "written the way the model writes it",
            )
        )
    # A repeated index: last write wins, the same rule the kernel case pins,
    # re-checked through the subscript.
    pair = pair_from_flat(torch_module, c_module, [0, 0, 0], (3,), "int64")
    idx = pair_from_flat(torch_module, c_module, [0, 0, 0], (3,), "int64")
    values = pair_from_flat(torch_module, c_module, [1, 2, 3], (3,), "int64")
    cases.append(
        _member_case(
            torch_module, c_module, op,
            "member x[idx] = values with a repeated index [last write wins]", "int64",
            [pair, idx, values], assigned(lambda a, i, v: a.__setitem__(i, v)),
            note="index [0,0,0] with values [1,2,3] leaves x[0] == 3",
        )
    )
    # A bool mask index. Upstream routes it through the same `index_put_`
    # (measured: `x[boolmask] = 1.0` dispatches `aten.index_put_.default`),
    # and this shim always resolved the *name* correctly and then refused
    # inside the kernel, which was written on top of `scatter` and so wanted
    # an int32/int64 index. **That was a missing kernel capability, not a
    # missing name**, and it was carried here as a `c_error` case until
    # docs/VIEWS.md §2 closed it. It is a real case now: a mask is a
    # different operation from an integer index, and the values are diffed.
    pair = pair_from_flat(torch_module, c_module, [0.0] * 4, (4,), "float32")
    mask = pair_from_flat(torch_module, c_module, [True, False, True, False], (4,), "bool")
    values = pair_from_flat(torch_module, c_module, [1.0, 2.0], (2,), "float32")
    cases.append(
        _member_case(
            torch_module, c_module, op,
            "member x[boolmask] = values (dtype=float32)",
            "float32", [pair, mask, values],
            assigned(lambda a, mk, v: a.__setitem__(mk, v)),
            note="measured [1,0,2,0] -- one value per TRUE position, in order, which is "
                 "not what reading the mask as an integer index would give",
        )
    )
    pair = pair_from_flat(torch_module, c_module, [0.0] * 4, (4,), "float32")
    mask = pair_from_flat(torch_module, c_module, [True, False, True, False], (4,), "bool")
    cases.append(
        _member_case(
            torch_module, c_module, op,
            "member x[boolmask] = 1.0 (dtype=float32) [a number against a mask]", "float32",
            [pair, mask], assigned(lambda a, mk: a.__setitem__(mk, 1.0)),
            note="the number is lifted to a 0-d tensor of the RECEIVER's dtype and "
                 "broadcast over the true positions -- both halves were gaps",
        )
    )
    # A 2-D mask over a 2-D receiver, which is `x[x > 0] = v` in the shape a
    # model writes it.
    pair = pair_from_flat(torch_module, c_module, [0.0] * 6, (2, 3), "float32")
    mask = pair_from_flat(
        torch_module, c_module, [True, False, True, False, True, False], (2, 3), "bool"
    )
    cases.append(
        _member_case(
            torch_module, c_module, op,
            "member x[bool 2-D mask] = 1.0 (dtype=float32)", "float32", [pair, mask],
            assigned(lambda a, mk: a.__setitem__(mk, 1.0)),
            note="measured [[1,0,1],[0,1,0]] -- the mask covers both axes, so each true "
                 "position is one element and not one row",
        )
    )

    # --- a receiver of rank above 1 (docs/VIEWS.md §3) ---------------------
    #
    # `x[idx] = v` on a matrix: the common shape, and the one the kernel
    # refused outright while it was built on `scatter`.
    for dtype_name in ["float32", "int64"]:
        zeros = [0] * 6
        pair = pair_from_flat(torch_module, c_module, zeros, (3, 2), dtype_name)
        idx = pair_from_flat(torch_module, c_module, [0, 2], (2,), "int64")
        values = pair_from_flat(
            torch_module, c_module, [1, 2, 3, 4], (2, 2), dtype_name
        )
        cases.append(
            _member_case(
                torch_module, c_module, op,
                f"member x[idx] = values on a (3,2) receiver (dtype={dtype_name})", dtype_name,
                [pair, idx, values], assigned(lambda a, i, v: a.__setitem__(i, v)),
                note="two whole rows replaced -- the indexing result is (2,2) and the "
                     "values arrive already that shape",
            )
        )
    # `x[t] = 5`, which is gap 3's headline: a Python number lifted to a 0-d
    # tensor and broadcast across every selected element. Two dtypes, because
    # the lift now follows the RECEIVER's dtype and an int on a float
    # receiver is exactly the pair that used to diverge.
    pair = pair_from_flat(torch_module, c_module, [0.0] * 6, (3, 2), "float32")
    idx = pair_from_flat(torch_module, c_module, [0, 2], (2,), "int64")
    cases.append(
        _member_case(
            torch_module, c_module, op,
            "member x[idx] = 5 on a (3,2) float32 receiver [an int number on a float tensor]",
            "float32", [pair, idx], assigned(lambda a, i: a.__setitem__(i, 5)),
            note="upstream lifts 5 to float32 because the RECEIVER is float32, not to "
                 "int64 because the number is an int -- and index_put_ refuses a dtype "
                 "mismatch, so getting the lift wrong refuses a write upstream performs",
        )
    )
    pair = pair_from_flat(torch_module, c_module, [0] * 4, (4,), "int64")
    idx = pair_from_flat(torch_module, c_module, [0, 2], (2,), "int64")
    cases.append(
        _member_case(
            torch_module, c_module, op,
            "member x[idx] = 5.0 on a 1-D int64 receiver [a float number on an int tensor]",
            "int64", [pair, idx], assigned(lambda a, i: a.__setitem__(i, 5.0)),
            note="the mirror of the case above: the lift is int64 and the number truncates",
        )
    )
    # `x[:, t] = v` -- the `[None, t]` index list, through the subscript that
    # produces it.
    pair = pair_from_flat(torch_module, c_module, [0.0] * 6, (2, 3), "float32")
    idx = pair_from_flat(torch_module, c_module, [0, 2], (2,), "int64")
    cases.append(
        _member_case(
            torch_module, c_module, op,
            "member x[:, idx] = 5.0 on a (2,3) receiver [indices [None, t]]", "float32",
            [pair, idx], assigned(lambda a, i: a.__setitem__((slice(None), i), 5.0)),
            note="measured [[5,0,5],[5,0,5]] -- columns, not rows, so a kernel that "
                 "ignored the leading None writes the wrong axis",
        )
    )
    # Negative indices through the subscript.
    pair = pair_from_flat(torch_module, c_module, [0.0] * 5, (5,), "float32")
    idx = pair_from_flat(torch_module, c_module, [-1, -2], (2,), "int64")
    values = pair_from_flat(torch_module, c_module, [1.0, 2.0], (2,), "float32")
    cases.append(
        _member_case(
            torch_module, c_module, op,
            "member x[negative idx] = values (dtype=float32)", "float32",
            [pair, idx, values], assigned(lambda a, i, v: a.__setitem__(i, v)),
            note="measured [0,0,0,2,1]",
        )
    )
    # A bool receiver with an integer number on the right. This is the pair
    # that tells the two lift rules apart at the *kernel* level rather than
    # only in the lift: `2` inferred from the Python type is int64, and
    # `index_put_` refuses a dtype mismatch, so the old rule turns a write
    # upstream performs into a refusal. Measured: `x[t] = 2` on a bool
    # receiver gives [True, False, False].
    pair = pair_from_flat(torch_module, c_module, [0, 0, 0], (3,), "bool")
    idx = pair_from_flat(torch_module, c_module, [0], (1,), "int64")
    cases.append(
        _member_case(
            torch_module, c_module, op,
            "member x[idx] = 2 on a bool receiver [the number lifts to bool, not int64]",
            "bool", [pair, idx], assigned(lambda a, i: a.__setitem__(i, 2)),
            note="2 is truthy, so the lifted 0-d bool is True; inferring int64 from the "
                 "Python type instead refuses here, which is a divergence from upstream "
                 "in the refusing direction rather than the computing one",
        )
    )
    # `x[:] = ...` on an int64 and a bool receiver. These go to `fill_.Tensor`
    # and not `index_put_`, so they cover the OTHER caller of `_lift`.
    #
    # **Neither of them discriminates between the two lift rules**, and that
    # is worth stating rather than implying: `fill_` takes its dtype from the
    # receiver on both sides, so an int64 value against a bool receiver still
    # comes out as the right bools. They are here because the fill_ path is
    # part of `__setitem__`'s measured behaviour, not because they guard the
    # lift. The `index_put_` case above is what guards the lift.
    pair = pair_from_flat(torch_module, c_module, [0, 0, 0], (3,), "int64")
    cases.append(
        _member_case(
            torch_module, c_module, "aten.fill_.Tensor",
            "member x[:] = 3.0 on an int64 receiver [fill_, and the value truncates]", "int64",
            [pair], assigned(lambda a: a.__setitem__(slice(None), 3.0)),
            note="upstream lifts to int64 because the receiver is int64; the result is "
                 "[3,3,3] and stays int64, which the dtype half of the comparator checks",
        )
    )
    pair = pair_from_flat(torch_module, c_module, [0, 0, 0], (3,), "bool")
    cases.append(
        _member_case(
            torch_module, c_module, "aten.fill_.Tensor",
            "member x[:] = 2 on a bool receiver [2 is truthy, so True]", "bool",
            [pair], assigned(lambda a: a.__setitem__(slice(None), 2)),
            note="measured [True,True,True] -- a receiver whose dtype cannot hold the "
                 "number, filled with what the number means rather than with its bits",
        )
    )
    # `x[:] = tensor` narrows nothing, so upstream reaches `copy_` rather than
    # `index_put_` -- measured -- and so does this.
    pair = pair_from_flat(torch_module, c_module, [0.0] * 4, (4,), "float32")
    src = pair_from_flat(torch_module, c_module, [1.0, 2.0, 3.0, 4.0], (4,), "float32")
    cases.append(
        _member_case(
            torch_module, c_module, "aten.copy_.default",
            "member x[:] = tensor (dtype=float32)", "float32", [pair, src],
            assigned(lambda a, s: a.__setitem__(slice(None), s)),
            note="measured: a full slice emits no narrowing op, so this is aten.copy_",
        )
    )
    pair = pair_from_flat(torch_module, c_module, [0.0] * 4, (4,), "float32")
    src = pair_from_flat(torch_module, c_module, [1.0, 2.0, 3.0, 4.0], (4,), "float32")
    cases.append(
        _member_case(
            torch_module, c_module, "aten.copy_.default",
            "member x[...] = tensor (dtype=float32)", "float32", [pair, src],
            assigned(lambda a, s: a.__setitem__(Ellipsis, s)),
            note="an ellipsis over every dimension expands to full slices",
        )
    )
    # ...and a scalar on the right of a full slice reaches `fill_`, not
    # `copy_`. Also measured, and the two are easy to conflate.
    pair = pair_from_flat(torch_module, c_module, [0.0] * 4, (4,), "float32")
    cases.append(
        _member_case(
            torch_module, c_module, "aten.fill_.Tensor",
            "member x[:] = 3.0 (dtype=float32) [fill_, not copy_]", "float32", [pair],
            assigned(lambda a: a.__setitem__(slice(None), 3.0)),
            note="measured: upstream lifts the number and dispatches aten.fill_.Tensor",
        )
    )

    # --- the basic-index half, which used to refuse ------------------------
    #
    # Each of these narrows to a view and writes through it. **The receiver is
    # what is compared** -- `__setitem__` returns `None`, so `assigned` hands
    # back the name that was subscripted and there is no return value a
    # write-into-a-copy could hide behind.
    #
    # Grouped by the op the walk lands on, because that is the thing easiest to
    # get wrong: `x[0] = 3.0` is `fill_` (a (3,) destination, a 0-d source) and
    # `x[0,1] = 9.0` is `copy_` (both 0-d), and the two differ only in shape.

    def basic(op_key, name, flat, shape, dtype_name, fn, note, extra=None):
        pairs = [pair_from_flat(torch_module, c_module, flat, shape, dtype_name)]
        if extra is not None:
            pairs.append(extra)
        cases.append(
            _member_case(
                torch_module, c_module, op_key, name, dtype_name, pairs,
                assigned(fn), note=note,
            )
        )

    grid = [float(v) for v in range(1, 13)]

    # **These cases cannot tell the two arms apart, and saying so is the
    # point.** They are filed under the key upstream dispatches and their
    # values are right, but `copy_` broadcasts a 0-d source to exactly what
    # `fill_` writes -- so routing every one of them to `copy_` instead leaves
    # the whole suite at 3075/3075 and all 229 smoke tests green (measured, by
    # deleting the `fill_` arm and rebuilding).
    #
    # Nor is the difference reachable another way here. The overflow refusal
    # that separates the two kernels (`fill_(float16, 1e6)` raises where
    # `copy_` gives `inf`) never fires, because `_lift` has already narrowed
    # the number to a 0-d tensor before either op sees it -- measured, both
    # sides give `inf` and both agree with upstream. And the capture facility,
    # which would show the op *name*, refuses to record any region containing
    # an in-place op at all.
    #
    # So the arm choice is carried because it is upstream's measured lowering
    # and because anything that ever observes the trace will depend on it --
    # not because these cases guard it. Written here rather than left for the
    # key to imply, the same way docs/VIEWS.md §2-§3 handled the `x[:] = 3.0`
    # case that could not discriminate the two `_lift` rules.

    # fill_ arm: destination bigger than the 0-d source.
    basic("aten.fill_.Tensor", "member x[0] = 3.0 (dtype=float32) [select.int, then fill_]",
          grid, (3, 4), "float32", lambda a: a.__setitem__(0, 3.0),
          "measured: [lift_fresh, select.int, fill_.Tensor] -- a row destination and a "
          "0-d source, so copy_to takes its fill_ arm")
    basic("aten.fill_.Tensor", "member x[:,1] = 7.0 (dtype=float32) [strided destination]",
          grid, (3, 4), "float32", lambda a: a.__setitem__((slice(None), 1), 7.0),
          "the destination is a column -- non-contiguous, which is the write "
          "tensor.rs::write_strided's odometer branch handles")
    basic("aten.fill_.Tensor", "member x[1:3] = 5.0 (dtype=float32)",
          grid, (3, 4), "float32", lambda a: a.__setitem__(slice(1, 3), 5.0),
          "measured: [lift_fresh, slice.Tensor, fill_.Tensor]")
    basic("aten.fill_.Tensor", "member x[None] = 4.0 (dtype=float32)",
          [0.0] * 3, (3,), "float32", lambda a: a.__setitem__(None, 4.0),
          "measured: [lift_fresh, unsqueeze, fill_.Tensor] -- unsqueeze aliases too")
    basic("aten.fill_.Tensor", "member x[-1] = 1.0 (dtype=float32) [negative index]",
          grid, (3, 4), "float32", lambda a: a.__setitem__(-1, 1.0),
          "select.int wraps a negative index; the write must land in the last row")

    # copy_ arm: destination and source the same size, including both 0-d.
    basic("aten.copy_.default", "member x[0,1] = 9.0 (dtype=float32) [copy_, not fill_]",
          grid, (3, 4), "float32", lambda a: a.__setitem__((0, 1), 9.0),
          "measured: [lift_fresh, select.int, select.int, copy_.default] -- a 0-d "
          "destination and a 0-d source are the same size, so copy_to takes its first arm")
    basic("aten.copy_.default", "member x[...] = 3.0 on a 0-d receiver [copy_, not fill_]",
          [0.0], (), "float32", lambda a: a.__setitem__(Ellipsis, 3.0),
          "the same rule as x[0,1], reached without any narrowing at all")
    basic("aten.copy_.default", "member x[0] = 2.7 (dtype=int64) [truncates, no promotion]",
          [0, 0, 0], (3,), "int64", lambda a: a.__setitem__(0, 2.7),
          "measured: upstream lifts to the receiver's dtype and copy_ truncates to 2")
    basic("aten.copy_.default", "member x[0] = True (dtype=bool)",
          [0, 0, 0], (3,), "bool", lambda a: a.__setitem__(0, True),
          "a bool receiver keeps its tag through the write")

    src = pair_from_flat(torch_module, c_module, [1.0, 2.0, 3.0, 4.0], (2, 2), "float32")
    basic("aten.copy_.default", "member x[1:3] = tensor(2,2) (dtype=float32)",
          [0.0] * 8, (4, 2), "float32", lambda a, s: a.__setitem__(slice(1, 3), s),
          "measured: [slice.Tensor, copy_.default] -- equal sizes, so no broadcast",
          extra=src)

    row = pair_from_flat(torch_module, c_module, [9.0, 8.0], (2,), "float32")
    basic("aten.copy_.default", "member x[1:3] = tensor(2,) (dtype=float32) [broadcast arm]",
          [0.0] * 8, (4, 2), "float32", lambda a, s: a.__setitem__(slice(1, 3), s),
          "measured: [slice.Tensor, view, expand, copy_] -- copy_to's third arm, which "
          "this shim reaches through copy_'s own broadcast",
          extra=row)

    # A step above 1 refuses here and computes upstream, because `slice.Tensor`
    # materialises rather than narrowing above step 1. `c_error` is the honest
    # expectation: the gap is recorded, and the case fails if the refusal ever
    # turns into a silent no-op.
    pair = pair_from_flat(torch_module, c_module, [1.0, 2.0, 3.0, 4.0], (4,), "float32")
    cases.append(
        _member_case(
            torch_module, c_module, "aten.copy_.default",
            "member x[0:4:2] = 0.0 [refused -- a step > 1 slice is not a view here]",
            "float32", [pair], assigned(lambda a: a.__setitem__(slice(0, 4, 2), 0.0)),
            expect="c_error",
            note="upstream writes through the stepped view; this shim refuses by name "
                 "rather than writing into the copy index_select made. The underlying "
                 "divergence has its own diverge case in slice_cases -- docs/VIEWS.md §6.4",
        )
    )
    return cases


# --- docs/ARCH20.md: the seven blocked architectures ------------------------
#
# Eleven new keys, and the split between them is the round's own finding: only
# three are new *kernels* (`log`, `expm1`, `constant_pad_nd`) plus one
# out-of-place sibling of an existing one (`clamp`); the other seven are the
# in-place arithmetic family, which is job two.
#
# Every in-place builder below ends by pulling its own cases out of
# `_view_write_cases`, which read the BASE rather than the return value. That
# is the check that can actually fail against a kernel that computes into a
# fresh buffer -- see that function's docstring for the round where 3037 cases
# were green while no in-place write was visible through any view.


def log_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.log.default"
    cases: list[Case] = []
    scenarios = [
        ([1.0, 2.0, 10.0, 0.5], (2, 2), "assorted positive"),
        ([1.0], (), "0-d"),
        # The domain edges, which are *values* upstream returns and not
        # errors -- measured, and the reason `unary_float` needed no domain
        # guard. `mamba`'s own input never leaves the positive half, so this
        # is the half of the op its caller could not have pinned.
        ([0.0, -1.0, -0.0], (3,), "log(0)=-inf, log(-1)=nan, log(-0.0)=-inf -- NOT errors"),
        ([float("inf"), float("nan")], (2,), "inf -> inf, nan -> nan"),
    ]
    for dtype_name in _TANH_DTYPES:
        for flat, shape, note in scenarios:
            cases.append(_unary_case(torch_module, c_module, op, torch_call, dtype_name, flat, shape, note))
    # The promotion rule, re-measured rather than assumed from `exp`.
    for dtype_name in _TANH_PROMOTING_DTYPES:
        cases.append(
            _unary_case(
                torch_module, c_module, op, torch_call, dtype_name, [1, 2, 3, 4], (2, 2),
                "integral input promotes to the default float, same rule as exp/tanh",
            )
        )
    cases.extend(_log_member_cases(torch_module, c_module))
    return cases


def _log_member_cases(torch_module, c_module) -> list[Case]:
    """`torch.log(x)` and `x.log()` -- the two spellings `mamba` and a caller
    reach, as opposed to the dispatch key the builder above uses.

    Deleting the `overloads.json` entry fails the first of these and nothing
    else; deleting the `methods.json` entry fails the second."""
    op = "aten.log.default"
    cases: list[Case] = []
    for spelling, call in (
        ("torch.log(x)", lambda m, a: m.log(a) if hasattr(m, "log") else m._VariableFunctions.log(a)),
        ("x.log()", lambda m, a: a.log()),
    ):
        for dtype_name in ["float32", "float64", "int64"]:
            pair = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (2, 2), dtype_name)
            cases.append(
                _member_case(
                    torch_module, c_module, op,
                    f"spelling {spelling} (dtype={dtype_name})", dtype_name, [pair], call,
                    note="mamba's init_mamba_weights: init.copy_(A_log, torch.log(A))",
                )
            )
    return cases


def expm1_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.expm1.default"
    cases: list[Case] = []
    scenarios = [
        ([0.0, 1.0, -1.0, 2.0], (2, 2), "assorted"),
        ([0.0], (), "0-d -- expm1(0) is exactly 0.0"),
        # THE case. `exp(x) - 1` loses every significant bit here; measured
        # upstream float64 expm1(1e-8) = 1.0000000050000001e-08 against
        # exp(1e-8)-1 = 9.99999993922529e-09. A subtraction-based kernel
        # passes every other case in this builder and fails this one.
        ([1e-8, -1e-8, 1e-12, -1e-12], (4,), "near zero -- where exp(x)-1 cancels"),
        ([-1000.0, 1000.0], (2,), "underflow to -1.0, overflow to inf"),
        ([float("nan"), float("inf"), float("-inf")], (3,), "nan, inf, -1.0"),
    ]
    for dtype_name in _TANH_DTYPES:
        for flat, shape, note in scenarios:
            cases.append(_unary_case(torch_module, c_module, op, torch_call, dtype_name, flat, shape, note))
    for dtype_name in _TANH_PROMOTING_DTYPES:
        cases.append(
            _unary_case(
                torch_module, c_module, op, torch_call, dtype_name, [0, 1, 2, 3], (2, 2),
                "integral input promotes to the default float, same rule as exp",
            )
        )
    return cases


def clamp_default_cases(torch_module, c_module, torch_call) -> list[Case]:
    """The out-of-place sibling of `clamp_.default`, `mamba`'s wall.

    Deliberately re-measures the rules `clamp_cases`' in-place twin already
    pins rather than assuming them: an out-of-place op *could* have promoted
    where the in-place one cannot, and it does not."""
    op = "aten.clamp.default"
    cases: list[Case] = []
    for dtype_name in ["float64", "float32", "float16", "bfloat16", "int64", "int32"]:
        for lo, hi, note in [
            (0, 5, "both bounds"),
            (None, 3, "max only -- min absent"),
            (2, None, "min only -- max absent"),
            (8, 2, "min > max: max(x,8) then min(...,2) gives all 2, NOT an error"),
        ]:
            a_t, a_c = pair_from_flat(
                torch_module, c_module, [1, 5, 10, -3], (4,), dtype_name
            )
            cases.append(
                Case(
                    name=f"clamp(dtype={dtype_name}, min={lo}, max={hi}) [{note}]",
                    op=op,
                    run_torch=lambda a_t=a_t, lo=lo, hi=hi: torch_call(a_t, lo, hi),
                    run_c=lambda a_c=a_c, lo=lo, hi=hi: c_module._aten_dispatch(op, a_c, lo, hi),
                    note=note,
                )
            )
    # NaN propagates through both steps, the same measurement `clamp_` pins.
    #
    # **Every lambda below binds its operands as default arguments.** Late
    # binding bit this builder once already: three cases shared the names
    # `a_t`/`a_c`, so all three ran against the *last* pair assigned and a
    # float32 case silently tested an int32 tensor.
    nan_t, nan_c = pair_from_flat(
        torch_module, c_module, [float("nan"), 1.0, -1.0], (3,), "float32"
    )
    cases.append(
        Case(
            name="clamp(float32, [nan,1,-1], 0, 2) [nan survives both bounds]",
            op=op,
            run_torch=lambda a=nan_t: torch_call(a, 0.0, 2.0),
            run_c=lambda a=nan_c: c_module._aten_dispatch(op, a, 0.0, 2.0),
            note="measured [nan, 1.0, 0.0] -- Rust's maximum/minimum return the NaN operand",
        )
    )
    # Both bounds absent is an ERROR, not a no-op. This is the rule a fresh
    # out-of-place implementation would most plausibly have got wrong, since
    # there is no receiver to leave unchanged.
    none_t, none_c = pair_from_flat(torch_module, c_module, [1.0, 2.0], (2,), "float32")
    cases.append(
        Case(
            name="clamp() with no bounds [refused on both sides, NOT a no-op]",
            op=op,
            run_torch=lambda a=none_t: torch_call(a, None, None),
            run_c=lambda a=none_c: c_module._aten_dispatch(op, a, None, None),
            expect="both_error",
            note="torch.clamp: At least one of 'min' or 'max' must not be None",
        )
    )
    # **The dtype rule, which is NOT clamp_'s.** The out-of-place form promotes
    # where the in-place one refuses, and the first draft of this builder
    # asserted the opposite -- these are the eight rows that caught it.
    #
    #     clamp(int32,  None, 2.0)    float32     clamp_ RAISES
    #     clamp(bool,   0,    5)      int64       clamp_ RAISES
    #
    # Both are read off upstream, not derived from `clamp_`.
    for dtype_name, flat, lo, hi, note in [
        ("int32", [1, 5, 10], None, 2.0, "a float bound floats an integral tensor -> float32"),
        ("int32", [1, 5, 10], 0, 5, "int bounds leave it int32"),
        ("int64", [1, 5, 10], None, 2.0, "int64 with a float bound -> float32, not float64"),
        ("uint8", [1, 5], None, 2, "uint8 with an int bound stays uint8"),
        ("uint8", [1, 5], None, 2.0, "uint8 with a float bound -> float32"),
        ("float16", [1.0, 5.0], None, 2.0,
         "a python float does NOT widen a float tensor -- stays float16"),
        ("float32", [1.0, 5.0, 10.0], 0, 5, "int bounds against a float tensor stay float32"),
        ("bool", [1, 0], 0, 5, "a bool tensor with int bounds promotes OUT of bool -> int64"),
        ("bool", [1, 0], 0.0, 1.0, "...and to float32 with float bounds"),
    ]:
        a_t, a_c = pair_from_flat(torch_module, c_module, flat, (len(flat),), dtype_name)
        cases.append(
            Case(
                name=f"clamp(dtype={dtype_name}, min={lo!r}, max={hi!r}) [{note}]",
                op=op,
                run_torch=lambda a=a_t, lo=lo, hi=hi: torch_call(a, lo, hi),
                run_c=lambda a=a_c, lo=lo, hi=hi: c_module._aten_dispatch(op, a, lo, hi),
                note=note,
            )
        )
    # The one row where the out-of-place form DOES refuse: a boolean scalar
    # does not lift a boolean tensor out of the bool category, and upstream has
    # no bool clamp kernel. `bool` subclasses `int` in Python, so telling this
    # apart from `clamp(bool_t, 0, 1)` above needs the raw argument.
    bool_t, bool_c = pair_from_flat(torch_module, c_module, [1, 0], (2,), "bool")
    cases.append(
        Case(
            name="clamp(bool, False, True) [refused -- the result would still be bool]",
            op=op,
            run_torch=lambda a=bool_t: torch_call(a, False, True),
            run_c=lambda a=bool_c: c_module._aten_dispatch(op, a, False, True),
            expect="both_error",
            note='NotImplementedError: "clamp_scalar_cpu" not implemented for \'Bool\' -- '
                 "and it is the case that separates a bool SCALAR from the integer 1",
        )
    )
    cases.extend(_clamp_member_cases_out_of_place(torch_module, c_module))
    return cases


def _clamp_member_cases_out_of_place(torch_module, c_module) -> list[Case]:
    """`x.clamp(...)`, the spelling `mamba` calls -- the member, not the key."""
    op = "aten.clamp.default"
    cases: list[Case] = []
    for dtype_name in ["float32", "int64"]:
        pair = pair_from_flat(torch_module, c_module, [1, 5, 10, -3], (4,), dtype_name)
        cases.append(
            _member_case(
                torch_module, c_module, op,
                f"member x.clamp(max=3) (dtype={dtype_name})", dtype_name, [pair],
                lambda m, a: a.clamp(max=3),
                note="mamba clamps dt out of place; only clamp_ had a kernel before",
            )
        )
    pair = pair_from_flat(torch_module, c_module, [1.0, 5.0, 10.0, -3.0], (4,), "float32")
    cases.append(
        _member_case(
            torch_module, c_module, op,
            "member x.clamp(0.0, 6.0) (dtype=float32, both bounds positional)",
            "float32", [pair], lambda m, a: a.clamp(0.0, 6.0),
            note="positional min/max bind the same overload the keyword form does",
        )
    )
    # The receiver must NOT be mutated -- the whole difference from clamp_.
    pair = pair_from_flat(torch_module, c_module, [1.0, 5.0, 10.0, -3.0], (4,), "float32")
    cases.append(
        _member_case(
            torch_module, c_module, op,
            "member x.clamp(0, 6) then read x [the RECEIVER, which must be unchanged]",
            "float32", [pair],
            lambda m, a: (a.clamp(0, 6), a)[1],
            note="out-of-place: a kernel that wrote through like clamp_ would pass a "
                 "return-value case and fail this one",
        )
    )
    # A tensor bound resolves clamp.Tensor, which has no kernel. Upstream
    # computes; refusing by the name of the overload is the honest answer.
    pair = pair_from_flat(torch_module, c_module, [1.0, 5.0, 10.0], (3,), "float32")
    bound = pair_from_flat(torch_module, c_module, [2.0, 2.0, 2.0], (3,), "float32")
    cases.append(
        _member_case(
            torch_module, c_module, op,
            "member x.clamp(min=<tensor>) [resolves clamp.Tensor, which has no kernel]",
            "float32", [pair, bound], lambda m, a, b: a.clamp(min=b),
            expect="c_error",
            note="recorded gap: aten::clamp.Tensor is a separate kernel this shim does "
                 "not have; methods.json lists it so the refusal names the overload",
        )
    )
    return cases


def constant_pad_nd_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.constant_pad_nd.default"
    cases: list[Case] = []

    def pad_case(name, flat, shape, dtype_name, pad, value, note, expect="match"):
        a_t, a_c = pair_from_flat(torch_module, c_module, flat, shape, dtype_name)
        args_t = (a_t, pad) if value is None else (a_t, pad, value)
        args_c = (a_c, pad) if value is None else (a_c, pad, value)
        cases.append(
            Case(
                name=name,
                op=op,
                run_torch=lambda args_t=args_t: torch_call(*args_t),
                run_c=lambda args_c=args_c: c_module._aten_dispatch(op, *args_c),
                expect=expect,
                note=note,
            )
        )

    grid = [float(v) for v in range(6)]
    # THE ordering case: the two dimensions get *different* pads, so a
    # front-to-back reading of `pad` produces a differently shaped answer and
    # cannot pass. Measured upstream: (2,3) -> (4,5).
    pad_case("constant_pad_nd((2,3), pad=[1,1,2,0], value=7.0) [pad is LAST-dim-first]",
             grid, (2, 3), "float32", [1, 1, 2, 0], 7.0,
             "upstream (4,5): pad[0:2] is the last dim, pad[2:4] the one before it")
    pad_case("constant_pad_nd((2,3), pad=[1,2], value=9.0) [last dim only]",
             grid, (2, 3), "float32", [1, 2], 9.0, "shorter pad leaves leading dims alone")
    pad_case("constant_pad_nd((2,3), pad=[1,1]) [default value=0]",
             grid, (2, 3), "float32", [1, 1], None,
             "the schema default is 0 and it is an integer there")
    pad_case("constant_pad_nd((2,3), pad=[]) [empty pad is the identity]",
             grid, (2, 3), "float32", [], None, "no pairs, nothing to do")
    pad_case("constant_pad_nd((2,3), pad=[0,0,0,0], value=9.0) [zeros are also identity]",
             grid, (2, 3), "float32", [0, 0, 0, 0], 9.0, "a zero pad must not add a block")
    # Negative entries crop, including crop-and-pad on the SAME axis.
    pad_case("constant_pad_nd((2,3), pad=[-1,0]) [negative crops the front]",
             grid, (2, 3), "float32", [-1, 0], None, "upstream [[1,2],[4,5]]")
    pad_case("constant_pad_nd((2,3), pad=[-1,-1]) [crops both ends]",
             grid, (2, 3), "float32", [-1, -1], None, "upstream [[1],[4]]")
    pad_case("constant_pad_nd((2,3), pad=[-1,2]) [crop AND pad on one axis]",
             grid, (2, 3), "float32", [-1, 2], None,
             "upstream [[1,2,0,0],[4,5,0,0]] -- crop first, then pad")
    pad_case("constant_pad_nd((2,3), pad=[-2,-2]) [crops past the axis]",
             grid, (2, 3), "float32", [-2, -2], None,
             "narrow(): length must be non-negative.", expect="both_error")
    # 1-D and 0-d.
    pad_case("constant_pad_nd((4,), pad=[0,3]) [1-D]",
             [0.0, 1.0, 2.0, 3.0], (4,), "float32", [0, 3], 0.0,
             "the bert shape: a bias vector extended at the back")
    pad_case("constant_pad_nd(0-d, pad=[]) [0-d stays 0-d]",
             [5.0], (), "float32", [], None, "no axis to pad")
    # Shape refusals, with upstream's exact (mis-spaced) messages.
    pad_case("constant_pad_nd((2,3), pad=[1]) [odd pad length]",
             grid, (2, 3), "float32", [1], None,
             "Length of pad must be even but instead it equals 1", expect="both_error")
    pad_case("constant_pad_nd((2,3), pad=[1]*6) [more pairs than dimensions]",
             grid, (2, 3), "float32", [1, 1, 1, 1, 1, 1], None,
             "Pad length is 6while the input has 2dimensions.", expect="both_error")
    # dtypes, and the fill conversion rules `filled_block` shares with `full`.
    for dtype_name, value, note in [
        ("float64", 2.5, "float64 fill"),
        ("float16", 2.5, "float16 keeps its own dtype"),
        ("bfloat16", 2.5, "bfloat16 keeps its own dtype"),
        ("int64", 3, "integer fill into an integer tensor"),
        ("int64", 3.7, "a FLOAT fill into an int64 tensor truncates toward zero -> 3"),
        ("int32", -2, "negative integer fill"),
        ("uint8", 7, "unsigned"),
        ("bool", True, "a bool fill is truthiness, and the tag survives"),
        ("bool", False, "the false fill, so the case is not passed by an all-True answer"),
    ]:
        pad_case(f"constant_pad_nd((1,2), pad=[1,1], dtype={dtype_name}, value={value!r}) [{note}]",
                 [1, 2], (1, 2), dtype_name, [1, 1], value, note)
    pad_case("constant_pad_nd((2,3), pad=[1,0], value=-inf) [an infinite fill]",
             grid, (2, 3), "float32", [1, 0], float("-inf"),
             "the attention-mask shape of fill, which must not become a finite number")
    # The overflow refusal `full` already makes, reached through the pad fill.
    pad_case("constant_pad_nd(int32, value=2**40) [fill does not fit the dtype]",
             [1, 2], (1, 2), "int32", [1, 1], 2 ** 40,
             "value cannot be converted to type int without overflow", expect="both_error")
    return cases


# --- the in-place arithmetic family (docs/ARCH20.md §8) ---------------------

_INPLACE_ARITH_DTYPES = ["float64", "float32", "float16", "bfloat16", "int64", "int32"]


def _inplace_tensor_cases(torch_module, c_module, torch_call, op, spell) -> list[Case]:
    """The shared body of `sub_.Tensor` and `mul_.Tensor`'s builders.

    A fresh operand pair per case, never shared -- an earlier mutation would
    otherwise leak into a later expectation."""
    cases: list[Case] = []
    for dtype_name in _INPLACE_ARITH_DTYPES:
        dst_t, dst_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (2, 2), dtype_name)
        src_t, src_c = pair_from_flat(torch_module, c_module, [5, 6, 7, 8], (2, 2), dtype_name)
        cases.append(
            Case(
                name=f"{spell}(dtype={dtype_name}, same shape)",
                op=op,
                run_torch=lambda dst_t=dst_t, src_t=src_t: torch_call(dst_t, src_t),
                run_c=lambda dst_c=dst_c, src_c=src_c: c_module._aten_dispatch(op, dst_c, src_c),
                note="in-place: compares the mutated dst operand the op returns",
            )
        )
    # `other` broadcasts INTO the receiver; never the other way round, which
    # is in-place's general rule.
    dst_t, dst_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4, 5, 6], (3, 2), "float32")
    src_t, src_c = pair_from_flat(torch_module, c_module, [2, 4, 5], (3, 1), "float32")
    cases.append(
        Case(
            name=f"{spell}(dtype=float32, other (3,1) broadcasts into (3,2))",
            op=op,
            run_torch=lambda: torch_call(dst_t, src_t),
            run_c=lambda: c_module._aten_dispatch(op, dst_c, src_c),
            note="broadcasting the source up to the destination's shape",
        )
    )
    # The cast check, both directions. The safe one computes; the unsafe one
    # refuses on BOTH sides (it used to compute here -- docs/ARCH20.md §8.3).
    dst_t, dst_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (2, 2), "float32")
    src_t, src_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (2, 2), "int32")
    cases.append(
        Case(
            name=f"{spell}(dtype=float32, other=int32) [promotes to float32, which fits]",
            op=op,
            run_torch=lambda: torch_call(dst_t, src_t),
            run_c=lambda: c_module._aten_dispatch(op, dst_c, src_c),
            note="canCast(Float -> Float) holds, so upstream computes and so does this",
        )
    )
    dst_t, dst_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (2, 2), "int32")
    src_t, src_c = pair_from_flat(torch_module, c_module, [1.5, 2.5, 3.5, 4.5], (2, 2), "float32")
    cases.append(
        Case(
            name=f"{spell}(dtype=int32, other=float32) [refused on BOTH sides]",
            op=op,
            run_torch=lambda: torch_call(dst_t, src_t),
            run_c=lambda: c_module._aten_dispatch(op, dst_c, src_c),
            expect="both_error",
            note="result type Float can't be cast to the desired output type Int -- this "
                 "shim used to compute a truncated answer here (docs/ARCH20.md §8.3)",
        )
    )
    return cases


def _inplace_scalar_cases(torch_module, c_module, torch_call, op, spell) -> list[Case]:
    cases: list[Case] = []
    for dtype_name in _INPLACE_ARITH_DTYPES:
        for scalar in (2, 2.0 if dtype_name.startswith(("float", "bfloat")) else 3):
            dst_t, dst_c = pair_from_flat(
                torch_module, c_module, [1, 2, 3, 4], (2, 2), dtype_name
            )
            cases.append(
                Case(
                    name=f"{spell}(dtype={dtype_name}, other={scalar!r})",
                    op=op,
                    run_torch=lambda dst_t=dst_t, s=scalar: torch_call(dst_t, s),
                    run_c=lambda dst_c=dst_c, s=scalar: c_module._aten_dispatch(op, dst_c, s),
                    note="the Scalar overload, in place",
                )
            )
    # A float scalar against an integral receiver promotes to float and then
    # cannot be cast back -- upstream's wrapped-number rule meeting canCast.
    dst_t, dst_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (2, 2), "int32")
    cases.append(
        Case(
            name=f"{spell}(dtype=int32, other=2.5) [refused on BOTH sides]",
            op=op,
            run_torch=lambda: torch_call(dst_t, 2.5),
            run_c=lambda: c_module._aten_dispatch(op, dst_c, 2.5),
            expect="both_error",
            note="result type Float can't be cast to the desired output type Int",
        )
    )
    return cases


def sub__tensor_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.sub_.Tensor"
    cases = _inplace_tensor_cases(torch_module, c_module, torch_call, op, "sub_")
    for alpha, note in [(2.0, "alpha scales other before it is subtracted"),
                        (-1.0, "a negative alpha turns sub_ into an add")]:
        dst_t, dst_c = pair_from_flat(torch_module, c_module, [1, 2, 3, 4], (2, 2), "float32")
        src_t, src_c = pair_from_flat(torch_module, c_module, [10, 20, 30, 40], (2, 2), "float32")
        cases.append(
            Case(
                name=f"sub_(dtype=float32, alpha={alpha}) [{note}]",
                op=op,
                run_torch=lambda dst_t=dst_t, src_t=src_t, alpha=alpha: torch_call(dst_t, src_t, alpha=alpha),
                run_c=lambda dst_c=dst_c, src_c=src_c, alpha=alpha: c_module._aten_dispatch(op, dst_c, src_c, alpha=alpha),
                note=note,
            )
        )
    # bool: upstream refuses subtraction on bool outright, and so does this.
    b_t, b_c = pair_from_flat(torch_module, c_module, [1, 0], (2,), "bool")
    o_t, o_c = pair_from_flat(torch_module, c_module, [1, 1], (2,), "bool")
    cases.append(
        Case(
            name="sub_(dtype=bool) [refused on both sides]",
            op=op,
            run_torch=lambda: torch_call(b_t, o_t),
            run_c=lambda: c_module._aten_dispatch(op, b_c, o_c),
            expect="both_error",
            note="upstream: 'Subtraction, the `-` operator, with a bool tensor is not "
                 "supported'; the shim refuses through arith_tag",
        )
    )
    cases.extend(_inplace_member_cases(torch_module, c_module, op, [
        ("x.sub_(y)", lambda m, a, b: a.sub_(b)),
        ("x -= y", lambda m, a, b: _isub(a, b)),
    ]))
    cases.extend(c for c in _view_write_cases(torch_module, c_module) if c.op == op)
    return cases


def mul__tensor_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.mul_.Tensor"
    cases = _inplace_tensor_cases(torch_module, c_module, torch_call, op, "mul_")
    # bool: `mul_` is the ONE arithmetic in-place op that accepts it, because
    # a bool product IS the logical and under the tag's 0/1 invariant.
    # Measured upstream: [True,False].mul_([True,True]) -> [True, False].
    b_t, b_c = pair_from_flat(torch_module, c_module, [1, 0], (2,), "bool")
    o_t, o_c = pair_from_flat(torch_module, c_module, [1, 1], (2,), "bool")
    cases.append(
        Case(
            name="mul_(dtype=bool) [computes -- the product IS the logical and]",
            op=op,
            run_torch=lambda: torch_call(b_t, o_t),
            run_c=lambda: c_module._aten_dispatch(op, b_c, o_c),
            note="the one bool arm arith_tag allows; add_/sub_ refuse it",
        )
    )
    cases.extend(_inplace_member_cases(torch_module, c_module, op, [
        ("x.mul_(y)", lambda m, a, b: a.mul_(b)),
        ("x *= y", lambda m, a, b: _imul(a, b)),
    ]))
    cases.extend(c for c in _view_write_cases(torch_module, c_module) if c.op == op)
    return cases


def add__scalar_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.add_.Scalar"
    cases = _inplace_scalar_cases(torch_module, c_module, torch_call, op, "add_")
    cases.extend(c for c in _view_write_cases(torch_module, c_module) if c.op == op)
    return cases


def sub__scalar_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.sub_.Scalar"
    cases = _inplace_scalar_cases(torch_module, c_module, torch_call, op, "sub_")
    cases.extend(c for c in _view_write_cases(torch_module, c_module) if c.op == op)
    return cases


def mul__scalar_cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.mul_.Scalar"
    cases = _inplace_scalar_cases(torch_module, c_module, torch_call, op, "mul_")
    cases.extend(c for c in _view_write_cases(torch_module, c_module) if c.op == op)
    # **The one scalar multiply upstream narrows** -- docs/SCALAR.md §2.2.
    # `mul.Scalar` widens, `div_.Scalar` widens, `x *= 0.3` widens, and
    # `torch.ops.aten.mul_.Scalar` alone does not (checked over 4096 values x 4
    # scalars x 2 dtypes, so it is not a vectorisation tail). Pinned rather than
    # left implicit, because it reads exactly like an op that was missed.
    cases.extend(
        _scalar_rule_cases(
            torch_module, c_module, op,
            lambda t, s: torch_call(t.clone(), s),
            lambda c, s: c_module._aten_dispatch(
                op, c_module._aten_dispatch("aten.clone.default", c), s
            ),
            rule="narrow",
            why="measured: this key, and only this key, disagrees with every "
                "other spelling of a reduced-float scalar multiply",
        )
    )
    return cases


def neg__cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.neg_.default"
    cases: list[Case] = []
    for dtype_name in ["float64", "float32", "float16", "bfloat16",
                       "int64", "int32", "int16"]:
        dst_t, dst_c = pair_from_flat(torch_module, c_module, [-2, -1, 0, 1, 2], (5,), dtype_name)
        cases.append(
            Case(
                name=f"neg_(dtype={dtype_name}) [keeps the dtype -- no promotion]",
                op=op,
                run_torch=lambda dst_t=dst_t: torch_call(dst_t),
                run_c=lambda dst_c=dst_c: c_module._aten_dispatch(op, dst_c),
                note="int64.neg_() is int64, measured -- unlike exp_, neg does not float",
            )
        )
    # uint8 wraps rather than raising, the same answer `neg.default` gives.
    dst_t, dst_c = pair_from_flat(torch_module, c_module, [1, 2, 0], (3,), "uint8")
    cases.append(
        Case(
            name="neg_(dtype=uint8) [wraps: 1 -> 255, 2 -> 254, 0 -> 0]",
            op=op,
            run_torch=lambda: torch_call(dst_t),
            run_c=lambda: c_module._aten_dispatch(op, dst_c),
            note="two's complement truncation, same as neg.default",
        )
    )
    dst_t, dst_c = pair_from_flat(
        torch_module, c_module, [float("nan"), float("inf"), -0.0, 0.0], (4,), "float32"
    )
    cases.append(
        Case(
            name="neg_(float32, [nan, inf, -0.0, 0.0]) [signs flip, nan survives]",
            op=op,
            run_torch=lambda: torch_call(dst_t),
            run_c=lambda: c_module._aten_dispatch(op, dst_c),
            note="-0.0 becomes 0.0 and 0.0 becomes -0.0; the harness compares bits",
        )
    )
    b_t, b_c = pair_from_flat(torch_module, c_module, [1, 0], (2,), "bool")
    cases.append(
        Case(
            name="neg_(dtype=bool) [refused on both sides]",
            op=op,
            run_torch=lambda: torch_call(b_t),
            run_c=lambda: c_module._aten_dispatch(op, b_c),
            expect="both_error",
            note="upstream points at ~ / logical_not(); the shim uses its exact wording",
        )
    )
    cases.extend(_inplace_member_cases(torch_module, c_module, op, [
        ("x.neg_()", lambda m, a: a.neg_()),
    ], operands=1))
    cases.extend(c for c in _view_write_cases(torch_module, c_module) if c.op == op)
    return cases


def exp__cases(torch_module, c_module, torch_call) -> list[Case]:
    op = "aten.exp_.default"
    cases: list[Case] = []
    for dtype_name in ["float64", "float32", "float16", "bfloat16"]:
        dst_t, dst_c = pair_from_flat(
            torch_module, c_module, [0.0, 1.0, -1.0, 2.0], (2, 2), dtype_name
        )
        cases.append(
            Case(
                name=f"exp_(dtype={dtype_name})",
                op=op,
                run_torch=lambda dst_t=dst_t: torch_call(dst_t),
                run_c=lambda dst_c=dst_c: c_module._aten_dispatch(op, dst_c),
                note="in-place exp; the receiver keeps its own float dtype",
            )
        )
    dst_t, dst_c = pair_from_flat(
        torch_module, c_module,
        [float("nan"), float("inf"), float("-inf"), -1000.0, 1000.0], (5,), "float32",
    )
    cases.append(
        Case(
            name="exp_(float32, [nan, inf, -inf, -1000, 1000])",
            op=op,
            run_torch=lambda: torch_call(dst_t),
            run_c=lambda: c_module._aten_dispatch(op, dst_c),
            note="nan, inf, 0.0, underflow to 0.0, overflow to inf",
        )
    )
    # THE difference between exp_ and exp: exp promotes an integral input,
    # and the in-place form has nowhere to put the promotion, so it refuses.
    for dtype_name in ["int64", "int32", "uint8", "bool"]:
        dst_t, dst_c = pair_from_flat(torch_module, c_module, [1, 2], (2,), dtype_name)
        cases.append(
            Case(
                name=f"exp_(dtype={dtype_name}) [refused -- exp promotes and in-place cannot]",
                op=op,
                run_torch=lambda dst_t=dst_t: torch_call(dst_t),
                run_c=lambda dst_c=dst_c: c_module._aten_dispatch(op, dst_c),
                expect="both_error",
                note="result type Float can't be cast to the desired output type Long/Int/"
                     "Byte/Bool -- exp.default computes float32 for exactly these inputs",
            )
        )
    cases.extend(_inplace_member_cases(torch_module, c_module, op, [
        ("x.exp_()", lambda m, a: a.exp_()),
    ], operands=1))
    cases.extend(c for c in _view_write_cases(torch_module, c_module) if c.op == op)
    return cases


def _isub(a, b):
    a -= b
    return a


def _imul(a, b):
    a *= b
    return a


def _iadd(a, b):
    a += b
    return a


def _inplace_member_cases(torch_module, c_module, op, spellings, operands=2) -> list[Case]:
    """In-place members, read back through the **base** of a view.

    Not through the return value: every in-place op returns `self`, so a
    return-value case passes against a kernel that computed into a fresh
    buffer -- and passes just as well against a *member* that resolved to the
    wrong overload, as long as that overload happened to compute the same
    thing. Each case here narrows `base[1]`, applies the member to the narrowed
    view, and returns the base.

    The `x += y` spellings matter separately from `x.add_(y)`: they go through
    `TensorBase.__iadd__`, a different `methods.json` key, and it was the
    missing one (docs/ARCH20.md §8)."""
    cases: list[Case] = []
    for label, call in spellings:
        def through_base(m, *tensors, call=call):
            base = tensors[0]
            view = base[1]
            call(m, view, *tensors[1:])
            return base

        a = pair_from_flat(
            torch_module, c_module, [1.0, 2.0, 3.0, 4.0, 5.0, 6.0], (3, 2), "float32"
        )
        pairs = [a]
        if operands == 2:
            pairs.append(
                pair_from_flat(torch_module, c_module, [2.0, 4.0], (2,), "float32")
            )
        cases.append(
            _member_case(
                torch_module, c_module, op,
                f"member {label} on a VIEW, then read the BASE (dtype=float32)",
                "float32", pairs, through_base,
                note="write-through: the mutation must be visible in base[1] afterwards, "
                     "which a kernel that rebound the view's wrapper would fail",
            )
        )
    return cases


def add__member_cases(torch_module, c_module) -> list[Case]:
    """`add_`/`__iadd__` -- the two members `aten.add_.Tensor` had no way in
    through until docs/ARCH20.md §8. `falcon`'s residual is `x += y`."""
    return _inplace_member_cases(torch_module, c_module, "aten.add_.Tensor", [
        ("x.add_(y)", lambda m, a, b: a.add_(b)),
        ("x += y", lambda m, a, b: _iadd(a, b)),
    ])


def relu__member_cases(torch_module, c_module) -> list[Case]:
    """`x.relu_()` -- the member for a kernel that had none since
    docs/KERNELS.md -- and `torch.relu_(x)`, the free function that had no
    `overloads.json` entry until docs/KERNELS26.md §21.

    `zoedepth` spells the free one (`transformers`' ZoeDepth neck runs
    `torch.relu_` on the fused feature maps), so the member alone was not
    enough. Same shape as `torch.detach` in §13: the kernel had been here and
    golden-compared the whole time, behind a door that did not exist."""
    return _inplace_member_cases(torch_module, c_module, "aten.relu_.default", [
        ("x.relu_()", lambda m, a: a.relu_()),
        ("torch.relu_(x)", lambda m, a: _free(m, "relu_")(a)),
    ], operands=1)


CASE_BUILDERS: dict[str, Callable[[Any, Any, Callable], list[Case]]] = {
    "aten._grouped_mm.default": grouped_mm_cases,
    "aten.full.default": full_cases,
    "aten.add.Tensor": add_cases,
    "aten.mm.default": mm_cases,
    # Pre-seeded ahead of implementation -- see the module note above.
    "aten.arange.default": arange_default_cases,
    "aten.arange.start": arange_start_cases,
    "aten.arange.start_step": arange_start_step_cases,
    "aten.argmax.default": argmax_cases,
    "aten.cat.default": cat_cases,
    "aten.embedding.default": embedding_cases,
    "aten.empty.memory_format": empty_cases,
    "aten.is_floating_point.default": is_floating_point_cases,
    "aten.isin.Tensor_Tensor": isin_cases,
    "aten.ones.default": ones_cases,
    "aten.pow.Tensor_Scalar": pow_tensor_scalar_cases,
    "aten.pow.Tensor_Tensor": pow_tensor_tensor_cases,
    "aten.pow.Scalar": pow_scalar_cases,
    "aten.randint.low": randint_low_cases,
    "aten.rsqrt.default": rsqrt_cases,
    "aten.sqrt.default": sqrt_cases,
    # docs/KERNELS26.md §17 -- sam3_video.
    "aten.sigmoid.default": sigmoid_cases,
    # docs/KERNELS26.md §18 -- vits.
    "aten.flip.default": flip_cases,
    "aten.repeat.default": repeat_cases,
    "aten.remainder.Scalar": remainder_scalar_cases,
    "aten.remainder.Tensor": remainder_tensor_cases,
    "aten.div.Scalar_mode": _div_mode_scalar_cases,
    "aten.div.Tensor_mode": _div_mode_tensor_cases,
    "aten.norm.ScalarOpt_dim": norm_scalaropt_dim_cases,
    "aten._weight_norm_interface.default": weight_norm_interface_cases,
    "aten.lift_fresh.default": lift_fresh_cases,
    # Pre-seeded ahead of implementation for TensorBase's 50 actually-used
    # members (docs/C_SURFACE.md §4) -- see the longer module note above.
    "aten.sub.Tensor": sub_cases,
    "aten.mul.Tensor": mul_cases,
    "aten.div.Tensor": div_cases,
    "aten.bitwise_and.Tensor": bitwise_and_tensor_cases,
    "aten.bitwise_and.Scalar": bitwise_and_scalar_cases,
    "aten.bitwise_or.Tensor": bitwise_or_tensor_cases,
    "aten.bitwise_or.Scalar": bitwise_or_scalar_cases,
    "aten.bitwise_not.default": bitwise_not_cases,
    "aten.eq.Tensor": eq_tensor_cases,
    "aten.eq.Scalar": eq_scalar_cases,
    "aten.lt.Tensor": lt_tensor_cases,
    "aten.lt.Scalar": lt_scalar_cases,
    "aten.ne.Tensor": ne_tensor_cases,
    "aten.ne.Scalar": ne_scalar_cases,
    "aten._local_scalar_dense.default": local_scalar_dense_cases,
    "aten.select.int": select_cases,
    "aten.slice.Tensor": slice_cases,
    "aten.index.Tensor": index_tensor_cases,
    "aten.amax.default": amax_cases,
    "aten.any.default": any_default_cases,
    "aten.any.dim": any_dim_cases,
    # docs/KERNELS26.md §16 -- sam3_video.
    "aten.all.default": all_default_cases,
    "aten.all.dim": all_dim_cases,
    "aten.all.dims": all_dims_cases,
    "aten.clone.default": clone_cases,
    "aten.detach.default": detach_cases,
    "aten.cos.default": cos_cases,
    "aten.sin.default": sin_cases,
    "aten.reciprocal.default": reciprocal_cases,
    "aten.cumsum.default": cumsum_cases,
    "aten.expand.default": expand_cases,
    "aten.masked_fill.Scalar": masked_fill_cases,
    "aten.max.default": max_default_cases,
    "aten.max.dim": max_dim_cases,
    "aten.mean.default": mean_default_cases,
    "aten.mean.dim": mean_dim_cases,
    "aten.sum.default": sum_default_cases,
    "aten.sum.dim_IntList": sum_dim_cases,
    "aten.new_ones.default": new_ones_cases,
    "aten.transpose.int": transpose_cases,
    "aten.unsqueeze.default": unsqueeze_cases,
    "aten.view.default": view_cases,
    "aten.view.dtype": view_dtype_cases,
    "aten._to_copy.default": to_copy_cases,
    "aten.fill_.Scalar": fill__cases,
    "aten.copy_.default": copy__cases,
    "aten.normal_.default": normal__cases,
    "aten.uniform_.default": uniform__cases,
    # The eight docs/GAP.md §3 measured a greedy 2-layer Llama stopping on.
    "aten.bmm.default": bmm_cases,
    "aten._unsafe_view.default": unsafe_view_cases,
    "aten.alias.default": alias_cases,
    "aten.neg.default": neg_cases,
    "aten.rsub.Scalar": rsub_scalar_cases,
    "aten.silu.default": silu_cases,
    "aten.t.default": t_cases,
    "aten._scaled_dot_product_flash_attention_for_cpu.default": sdpa_flash_cpu_cases,
    # The eight docs/SAMPLING.md measured `do_sample=True` stopping on.
    "aten._softmax.default": softmax_cases,
    "aten.fill_.Tensor": fill__tensor_cases,
    "aten.le.Scalar": le_scalar_cases,
    "aten.multinomial.default": multinomial_cases,
    "aten.scatter.src": scatter_src_cases,
    "aten.sort.default": sort_cases,
    "aten.squeeze.dim": squeeze_dim_cases,
    "aten.topk.default": topk_cases,
    # The four docs/GPT2.md measured a 2-layer GPT-2 stopping on, after the
    # Llama-shaped work had already cleared everything else.
    "aten.addmm.default": addmm_cases,
    "aten.native_layer_norm.default": native_layer_norm_cases,
    # docs/KERNELS26.md §19 -- sew_d.
    "aten.native_group_norm.default": native_group_norm_cases,
    # docs/KERNELS26.md §20 -- zoedepth.
    "aten.upsample_bilinear2d.default": upsample_bilinear2d_cases,
    "aten.split.Tensor": split_cases,
    "aten.tanh.default": tanh_cases,
    # What widening past the Llama/GPT-2 family asks for (docs/ARCH.md).
    "aten.gelu.default": gelu_cases,
    "aten.gather.default": gather_cases,
    "aten.zero_.default": zero__cases,
    # The four docs/ARCH.md measured falcon, gptj, bloom and mpt all missing --
    # the same four, in all four models -- plus the next two by architecture
    # count (docs/OPS4.md).
    "aten.le.Tensor": le_tensor_cases,
    "aten.scalar_tensor.default": scalar_tensor_cases,
    "aten.where.self": where_self_cases,
    # The eager attention mask's own op (docs/GENERATE.md): `torch.where(mask,
    # tensor, python_scalar)` at masking_utils.py:603.
    "aten.where.ScalarOther": where_scalar_other_cases,
    "aten.permute.default": permute_cases,
    "aten.stack.default": stack_cases,
    "aten.relu.default": relu_cases,
    # The five ops docs/TAIL.md needed to open falcon/bloom/gpt_bigcode.
    "aten.baddbmm.default": baddbmm_cases,
    "aten.split_with_sizes.default": split_with_sizes_cases,
    "aten._safe_softmax.default": safe_softmax_cases,
    # docs/LOSS.md -- the cross-entropy forward.
    "aten._log_softmax.default": log_softmax_cases,
    "aten.nll_loss_forward.default": nll_loss_forward_cases,
    "aten.native_dropout.default": native_dropout_cases,
    "aten.add_.Tensor": add__tensor_cases,
    "aten.mul.Scalar": mul_scalar_cases,
    # docs/KERNELS.md: the in-place sibling `F.relu(..., inplace=True)` traces
    # to, landed as its own kernel (was a measured gap, docs/SPELLINGS.md §6.6).
    "aten.relu_.default": relu__cases,
    # mamba and mixtral, the last two of the 20 measured architectures
    # (docs/OPS4.md) with anything unimplemented.
    "aten.exp.default": exp_cases,
    # docs/KERNELS26.md §22 -- sew_d.
    "aten.erf.default": erf_cases,
    "aten.sign.default": sign_cases,
    "aten.avg_pool2d.default": avg_pool2d_cases,
    "aten.log2.default": log2_cases,
    "aten.leaky_relu.default": leaky_relu_cases,
    "aten.softplus.default": softplus_cases,
    "aten.convolution.default": convolution_cases,
    "aten.zeros_like.default": zeros_like_cases,
    "aten.ones_like.default": ones_like_cases,
    "aten.empty_like.default": empty_like_cases,
    "aten.ge.Scalar": ge_scalar_cases,
    "aten.ge.Tensor": ge_tensor_cases,
    "aten.floor_divide.default": floor_divide_cases,
    "aten.floor_divide.Scalar": floor_divide_scalar_cases,
    "aten.histc.default": histc_cases,
    "aten.clamp_.default": clamp__default_cases,
    # docs/ARCH20.md -- the seven blocked architectures, and the in-place
    # family that had kernels but no names.
    "aten.clamp.default": clamp_default_cases,
    # docs/KERNELS26.md §15 -- vits.
    "aten.clamp_min.default": clamp_min_default_cases,
    "aten.log.default": log_cases,
    "aten.expm1.default": expm1_cases,
    "aten.constant_pad_nd.default": constant_pad_nd_cases,
    "aten.sub_.Tensor": sub__tensor_cases,
    "aten.sub_.Scalar": sub__scalar_cases,
    "aten.mul_.Tensor": mul__tensor_cases,
    "aten.mul_.Scalar": mul__scalar_cases,
    "aten.add_.Scalar": add__scalar_cases,
    "aten.neg_.default": neg__cases,
    "aten.exp_.default": exp__cases,
    "aten.div_.Tensor": div__tensor_cases,
    "aten.masked_fill_.Scalar": masked_fill__scalar_cases,
    "aten.index_put_.default": index_put__cases,
    # The six ops `repr(tensor)` dispatches that this shim lacked, measured
    # with a TorchDispatchMode logger around torch._tensor_str._str_intern.
    "aten.abs.default": abs_cases,
    "aten.ceil.default": ceil_cases,
    "aten.gt.Tensor": gt_tensor_cases,
    "aten.gt.Scalar": gt_scalar_cases,
    "aten.masked_select.default": masked_select_cases,
    "aten.min.default": min_default_cases,
    "aten.unbind.int": unbind_int_cases,
    # docs/LINEAR.md: the layout-fallback fix + N-D x 2-D fold, and the case
    # builder that moves this op from IMPLEMENTED_AWAITING_GOLDEN into the
    # 2760-case golden suite (docs/LINEAR.md §4.3, §6 item 2).
    "aten.matmul.default": matmul_cases,
    # docs/SPELLINGS.md: the two `IMPLEMENTED_AWAITING_GOLDEN` kernels that
    # fell inside this round's 25-name inventory, moved into real coverage.
    # `max.other`'s builder was written while the op was still parked, and it
    # found a live NaN defect and held it as a failing case until docs/TRIL.md
    # §3 fixed the kernel; the op is promoted into `_aten_implemented()` there.
    "aten.max.other": max_other_cases,
    "aten.reshape.default": reshape_cases,
    # docs/TRIL.md: GPT-BigCode's last wall and its mirror, plus the `min` half
    # of the max/min family, which had spelling-table entries and no kernels.
    "aten.tril.default": tril_cases,
    "aten.triu.default": triu_cases,
    "aten.min.dim": min_dim_cases,
    "aten.min.other": min_other_cases,
    # docs/TRAIN.md: training mode. `bernoulli__float_cases` also carries the
    # `torch.dropout` composite, which has no dispatch key of its own to be
    # registered under -- `aten::dropout` is CompositeImplicitAutograd and
    # never reaches the dispatcher, so golden is structurally blind to it and
    # it has to ride on the kernel it decomposes onto.
    "aten.bernoulli_.float": bernoulli__float_cases,
    "aten.div_.Scalar": div__scalar_cases,
}
