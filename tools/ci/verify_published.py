"""Does the published wheel compute, on a platform this project cannot run?

The README's `computes` row is ⚠️ for Linux and Windows. The wheels are on PyPI
and `tools/wheel/verify_linux.py` / `verify_windows.py` confirm every symbol
resolves, but resolving is not running: this project's only machine is an arm64
Mac with no Linux, no Windows and no container runtime. A hosted runner is the
missing machine, and this is what it runs.

**Every expected value here was produced on macOS arm64 from the same source.**
That is the point of hardcoding them rather than computing a tolerance: a
mismatch localises to the platform, because the arithmetic is identical.

Exits non-zero on the first disagreement, so the workflow fails loudly rather
than leaving a wrong number in a log nobody reads.
"""

import sys


FAILURES = []


def check(name, got, want):
    ok = got == want
    print(f"{'PASS' if ok else 'FAIL'}  {name:<34} {got!r}")
    if not ok:
        print(f"      {'':<34} expected {want!r}")
        FAILURES.append(name)
    return ok


def provenance():
    """Which `torch` is this, before anything is asked of it.

    `_aten_implemented` exists only on the shim. A run that reaches upstream's
    `torch` instead -- because a dependency pulled one in and pip replaced ours
    -- would otherwise pass every check below while proving nothing, which is a
    mistake this project has already made once on its own machine.
    """
    import torch

    print("torch          :", torch.__version__)
    print("torch.__file__ :", torch.__file__)
    is_shim = hasattr(torch._C, "_aten_implemented")
    check("this is the shim, not upstream", is_shim, True)
    if not is_shim:
        print("\nSTOP: upstream torch is installed here. Nothing below would mean anything.")
        raise SystemExit(1)
    print("aten ops       :", len(torch._C._aten_implemented()))
    return torch


def kernels(torch):
    a = torch.ones(2, 3)
    b = torch.ones(3, 4)
    check("mm shape", tuple((a @ b).shape), (2, 4))
    check("mm sum", (a @ b).sum().item(), 24.0)

    lin = torch.nn.Linear(3, 4, bias=False)
    with torch.no_grad():
        lin.weight.fill_(1.0)
        out = lin(torch.ones(1, 3))
    check("nn.Linear sum", out.sum().item(), 12.0)


def promotion(torch):
    """0.0.9a0's mixed-dtype promotion, chosen for where it is easy to get wrong.

    Upstream casts each operand to the common dtype *first* and only then to the
    accumulator. Both routes label the result `float16`; only one of them says
    2047. The comparison is worse -- the result is `bool` either way, so nothing
    about the type betrays a wrong answer.
    """
    x = torch.tensor([2049], dtype=torch.int64)
    y = torch.tensor([1.0], dtype=torch.float16)
    check("sub(int64,float16) value", torch.sub(x, y).tolist(), [2047.0])
    check("sub(int64,float16) dtype", str(torch.sub(x, y).dtype), "torch.float16")

    check(
        "eq(int64,float32) at 2**24+1",
        torch.eq(torch.tensor([16777217]), torch.tensor([16777216.0])).tolist(),
        [True],
    )

    f32 = torch.tensor([0.1])
    f64 = torch.tensor([0.1], dtype=torch.float64)
    check("cat promotes to float64", str(torch.cat([f32, f64]).dtype), "torch.float64")
    check(
        "sub(f32,f64) value",
        torch.sub(f32, f64).tolist(),
        [1.4901161138336505e-09],
    )

    # And a pair upstream itself refuses, so "promotes everything" would fail here.
    try:
        torch.mm(torch.ones(2, 2), torch.ones(2, 2, dtype=torch.float64))
        check("mm refuses a mixed pair", "computed", "raised")
    except Exception as exc:
        check("mm refuses a mixed pair", type(exc).__name__ != "", True)
        print(f"      {'':<34} {str(exc).splitlines()[0][:80]}")


def model(torch):
    """A real checkpoint through real transformers -- the premise of the project.

    Greedy and short so the text is deterministic and comparable. The string is
    what macOS arm64 produced; a platform that imports and computes small
    kernels correctly can still diverge here, which is why this is separate from
    the arithmetic above.
    """
    import time

    from transformers import AutoModelForCausalLM, AutoTokenizer

    name = "HuggingFaceTB/SmolLM2-135M"
    m = AutoModelForCausalLM.from_pretrained(name, dtype=torch.float32)
    m.eval()
    tok = AutoTokenizer.from_pretrained(name)
    inp = tok("On-device inference is", return_tensors="pt")

    with torch.no_grad():
        m.generate(**inp, max_new_tokens=4, do_sample=False, use_cache=True)
        t0 = time.perf_counter()
        out = m.generate(**inp, max_new_tokens=24, do_sample=False, use_cache=True)
        dt = time.perf_counter() - t0

    text = tok.decode(out[0], skip_special_tokens=True)
    print(f"generated : {text!r}")
    print(f"speed     : {dt * 1000:.1f} ms for 24 tokens -> {24 / dt:.1f} tok/s")
    check(
        "generated text matches macOS arm64",
        text.startswith("On-device inference is a very powerful technique for learning from data."),
        True,
    )


def quantised(torch):
    """Load-time quantisation, which is the on-device path this exists for.

    Skipped, loudly and by name, when the installed release predates the
    feature. This runs against **published** wheels, so a check written today
    will outrun the version on PyPI until the next release -- and reporting that
    as a platform failure would be a lie about the platform. The version is
    printed so the skip cannot quietly become permanent.
    """
    import importlib.metadata as md

    from transformers import AutoModelForCausalLM

    try:
        from torchnative.quant import TorchnativeConfig
    except ImportError:
        print(
            f"SKIP  load-time quantisation -- torchnative "
            f"{md.version('torchnative')} predates TorchnativeConfig. "
            f"Not a platform result."
        )
        return

    m = AutoModelForCausalLM.from_pretrained(
        "HuggingFaceTB/SmolLM2-135M",
        dtype=torch.float32,
        quantization_config=TorchnativeConfig("q8_0"),
    )
    kinds = {}
    for mod in m.modules():
        kinds[type(mod).__name__] = kinds.get(type(mod).__name__, 0) + 1
    check("QuantizedLinear count", kinds.get("QuantizedLinear", 0), 210)
    check("Linear left dense (lm_head)", kinds.get("Linear", 0), 1)


def main():
    want_model = "--model" in sys.argv
    torch = provenance()
    if want_model:
        model(torch)
        quantised(torch)
    else:
        kernels(torch)
        promotion(torch)

    print()
    if FAILURES:
        print(f"RESULT: {len(FAILURES)} FAILED -- {', '.join(FAILURES)}")
        return 1
    print("RESULT: ALL PASS")
    return 0


if __name__ == "__main__":
    raise SystemExit(main())
