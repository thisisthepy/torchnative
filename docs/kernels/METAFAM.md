# METAFAM — closing the two families docs/architectures/VOICE4.md left open

Worktree `work/metafam` on develop `c6e4a3a`. Upstream torch 2.13.0
(`/Volumes/macMini/caches/spike-venv/bin/python`) is the oracle throughout, in its own
process with `PYTHONPATH` stripped -- the same method docs/architectures/VOICE4.md §6 and docs/numerics/AGREE.md
§2 use.

---

## 0. Answers first

| question | answer | where |
|---|---|---|
| What did VOICE4.md leave open, by name? | `aten.sum.default` and `aten.view.default` got meta kernels; their siblings (`sum.dim_IntList`, `mean.dim`, `reshape`, ...) did not. VOICE4.md §7 said so explicitly. | §1 |
| How many meta kernels did this round add? | **12**: `sum.dim_IntList`, `mean.dim`, `mean.default`, `cumsum.default`, `any.default`, `amax.default` (reduction family) and `reshape.default`, `t.default`, `transpose.int`, `permute.default`, `unsqueeze.default`, `squeeze.dim`, `squeeze.default`, `slice.Tensor` (view family) -- 6 + 8 = 14 names, 12 new functions (`slice.Tensor`'s complex-input arm and `unsqueeze.default`'s complex-input arm already existed and are untouched). | §3 |
| New operators? | **Zero.** Every op above was already in `_aten_implemented()` -- a dense kernel and golden cases, months old. | §3.1 |
| Was VOICE4's guessed priority (`sum.dim_IntList`, `mean.dim`, `reshape` "next") right? | **No.** Measured against real `from_pretrained` forward passes, the first wall hit is `aten.embedding.default` (5 of 7 architectures), then `slice.Tensor`, then `cumsum.default` -- a different family (contraction) ranks above the reduction/view families this round closed. See §2. | §2 |
| Did every kernel get tested against upstream across edge cases? | Yes -- `rust/torch_c/pytests/test_metafam.py`, 15 tests, ~140 individual probe cases across 0-dim, empty, keepdim, negative dims, dtype promotion, and refusals. | §4 |
| Did nullification catch real bugs? | **8/8 caught.** Every deliberately broken kernel went red. | §5 |
| Gate | 1021 ok / 0 FAIL, DOCWATCH 903/903, golden 11405/11405 pending 0 ops=302, cargo test 30/30. | §7 |
| Are the families fully closed? | **No.** `max.dim`, `argmax`, `topk`, `sort` (reduction) and `squeeze.dims`, `narrow`, `unfold`, `flip` (view), plus the contraction/indexing/composite/combine-split families §7.4 also lists, remain refused. See §6. | §6 |

---

## 1. What "the families" means

docs/devices/META.md §7.4 groups the 80 (now 68) ops with a dense kernel but no meta kernel into
eight columns. VOICE4.md §4 closed exactly two members, one from two of those columns:

| column | member VOICE4.md closed | siblings still open going in |
|---|---|---|
| 축소 (reduction), 21 ops | `sum.default` | `sum.dim_IntList`, `mean`, `amax`, `max.dim`, `argmax`, `any`, `cumsum`, `topk`, `sort`, ... |
| 뷰·모양 (view/shape), 12 ops | `view.default` | `reshape`, `t`, `permute`, `transpose`, `slice`, `squeeze`, `unsqueeze`, ... |

VOICE4.md §7 said this in its own words: "이 라운드가 닫은 것은 계열이 아니라 각 계열의 한
멤버입니다" ("what this round closed is not a family but one member of each family"). This
round's task is that sentence's imperative.

---

## 2. Deriving the current list, and the priority claim VOICE4 made without measuring it

### 2.1 Derivation, not the doc

Before writing anything, the current meta-kernel surface was read off `meta_dispatch`'s own
match arms in `rust/torch_c/src/aten.rs`, not off META.md §7.4's table:

```
grep -oE '"aten\.[a-zA-Z0-9_]+\.[a-zA-Z0-9_]+"|"prims\.[a-zA-Z0-9_]+\.[a-zA-Z0-9_]+"' \
    <(awk '/^fn meta_dispatch/,/^fn meta_result/' rust/torch_c/src/aten.rs) | sort -u
```

66 ops, going in. That reconciles exactly with META.md §7.4's own 2026-09 correction note
(148 implemented, 66 with a meta kernel including `sum.default`/`view.default`, 80 without) --
**the doc was not stale beyond what it had already corrected itself**, so no further dated
correction to META.md was needed from this step. The reconciliation is worth stating because
the instruction was to trust the derivation over the doc if they disagreed; here they agreed,
which is itself the check that matters (CLAUDE.md §5.4 -- "if the agent's conclusion matches
my hypothesis, that is when to suspect it hardest" applies here as "matches the doc", and the
match was verified by direct enumeration, not by re-reading the doc's prose).

### 2.2 The priority claim, checked against real models

VOICE4.md §7 named `sum.dim_IntList`, `mean.dim`, `reshape` as "next" -- but that was a
guess read off the table's ordering, not a measurement. It was checked two ways.

**Construction under `torch.device("meta")`** (the exact path VOICE4.md's own wall was on)
against ten real architectures (`gpt2`, `bert-base-uncased`, `mistralai/Mistral-7B-v0.1`,
`Qwen/Qwen2-7B`, `facebook/bart-base`, `openai/whisper-tiny`, `distilbert-base-uncased`,
`roberta-base`, plus two gated repos that 401'd): **all ten construct clean, zero meta-kernel
misses.** Construction alone does not discriminate -- the elementwise family plus
`select`/`tril`/`triu`/`expand` from earlier rounds already covers every `__init__` path these
architectures take.

**Forward pass under meta** (docs/devices/META.md §7.4 says this "여전히 안 됩니다" going in, and it
was right) is where the real ranking showed up:

```
gpt2                  -> aten.embedding.default   (first wall)
bert-base-uncased     -> aten.slice.Tensor
mistralai/Mistral-7B  -> aten.embedding.default
Qwen/Qwen2-7B         -> aten.embedding.default
facebook/bart-base     -> aten.embedding.default
distilbert-base-uncased -> aten.embedding.default
roberta-base           -> aten.cumsum.default

hit counts: aten.embedding.default x5, aten.slice.Tensor x1, aten.cumsum.default x1
```

**The measured ranking disagrees with VOICE4's guess.** `aten.embedding.default` -- a
CONTRACTION-family op (`mm`, `bmm`, `matmul`, `addmm`, `embedding` in META.md §7.4's own
grouping), not reduction or view -- is the first wall for 5 of 7 architectures. Neither
`sum.dim_IntList` nor `mean.dim` nor `reshape` was hit at all in this sweep (each probe stops
at the FIRST wall per architecture, so a family ranked second is invisible until the first is
closed -- this is a floor on the measurement, stated rather than hidden).

**This round did not fix `embedding.default`.** The task that produced this round was scoped
to the reduction and view families specifically -- VOICE4.md's own unclosed families, named by
title -- and `embedding` is a different family (contraction) with a different kind of shape
rule (it reads an index tensor's shape and the weight's last dim, not a straightforward
axis-reduction or axis-permutation). Reported here rather than silently substituted: the
measured next step for unblocking real forward passes is `embedding.default`, not the three
ops VOICE4 guessed, and that is left for a round scoped to the contraction family.

`slice.Tensor` and `cumsum.default` -- both closed by this round -- DO show up in the
measured ranking (bert and roberta respectively), so the round is not wasted relative to
measured demand; it is just not the top of it.

---

## 3. The twelve kernels

Every kernel below calls the SAME shape/dtype helper its dense sibling already factored out,
per META.md §7.1's rule restated in §0 above. None restate a rule the dense kernel owns.

| kernel | shape | dtype | shared with dense |
|---|---|---|---|
| `sum.dim_IntList` | `reduced_dims(extents, dims, keepdim)` | `sum_natural_tag` (same fn `sum.default`'s meta arm calls) | `reduced_dims`, `sum_natural_tag`, `reduce_dims` |
| `mean.dim` | `reduced_dims(...)` | input's own (refuses non-floating) | `reduced_dims`, `reduce_dims` |
| `mean.default` | rank 0 | input's own, refuses non-floating | same refusal wording as `sum_or_mean` |
| `cumsum.default` | unchanged (no reduction) | `sum_natural_tag` | `sum_natural_tag`, `normalise_dim` |
| `any.default` | rank 0 | `bool_reduce_tag` (bool, except `uint8` stays `uint8`) | `bool_reduce_tag` |
| `amax.default` | `reduced_dims(...)` | input's own (no widening) | `reduced_dims`, `first_repeat`, the two dense zero-numel refusals |
| `reshape.default` | `resolve_shape` + numel check | input's own | same helper `view.default`'s meta arm uses |
| `t.default` | 0/1-D unchanged, 2-D swap, 3-D+ refuses | input's own | `t_default`'s own rule, transcribed |
| `transpose.int` | swap two normalised axes | input's own | `normalise_dim` |
| `permute.default` | reorder by normalised `dims`, refuses wrong length/dup | input's own | `normalise_dim` |
| `unsqueeze.default` | insert size-1 at `[-(rank+1), rank]` | input's own | `unsqueeze_default`'s own range rule |
| `squeeze.dim` | remove axis IFF size 1 (else no-op) | input's own | `squeeze_dim`'s own no-op rule |
| `squeeze.default` | remove every size-1 axis | input's own | `squeeze_default`'s own rule |
| `slice.Tensor` | clamp start/end, step-aware length | input's own | `slice_tensor`'s own clamp arithmetic |

Implementation: `rust/torch_c/src/aten.rs`, in `meta_dispatch`, immediately after the
`aten.view.default` arm. A shared helper, `reduce_dims_or_all`, factors the
`None`/`Some([])` -> "every axis" collapse that `sum`/`mean`/`amax`'s meta arms all need
(this collapse is a property of what EMPTY means to a given op -- `squeeze.dims` treats it
oppositely, "no-op", and is written out at its own call site rather than sharing this helper,
matching how the dense side already handles it).

### 3.1 The bug this round found and fixed in itself, before landing

The first draft of every new arm called `input.tensor()?.rank()` / `.elem_count()` to read
shape metadata -- copying the pattern the DENSE kernels use, where `.tensor()` returns the
candle `Tensor` holding real storage. On a meta `PyTensorBase`, `.tensor()` refuses
(`tensor.rs:327`, `Cannot copy out of meta tensor; no data!`) precisely because there is no
storage to return. Every new kernel failed with that message on first build+run, for every
input, including ones that should have answered cleanly.

The fix: use `.dims()` (metadata-only, works on any `Repr`) instead of `.tensor()?.dims()`/
`.rank()`/`.elem_count()` throughout. `sum.default` and `view.default`'s existing meta arms
already did this correctly -- their pattern was there to copy, and the new arms did not, at
first. Caught by §5's sanity probe (every op initially answered `NotImplementedError:
Cannot copy out of meta tensor; no data!` instead of a shape), not by a golden test, because
a meta kernel has no golden case (§7).

### 3.2 `reshape` answering from `view`'s rule

META.md §7.4's note (added when VOICE4.md closed `view` but not `reshape`) reads: "`reshape`
는 *복사할 수* 있으므로 `view`의 규칙으로 답하면 상류가 복사를 돌려줄 자리에서 뷰를 약속하게
됩니다" -- reshape may copy, so answering it from view's rule promises a view where upstream
might return a copy.

> **Superseded by `docs/graph/STRIDE.md`:** a meta tensor carries a layout and a storage
> identity now, so view and copy are distinguishable, and `reshape`'s meta arm picks
> between them by upstream's `computeStride` rule.

That is a claim about ALIASING. A meta tensor in this shim carries no storage and no strides
at all (META.md §7.2's own note on `expand`: "이 셰임의 meta expand는 모양만 맞고 스트라이드
의미는 없습니다"), so "the result aliases the input" and "the result is a fresh copy" are
INDISTINGUISHABLE outputs on a meta tensor -- same shape, same dtype, no data either way.
Shape and dtype are the entire content of what a meta kernel can promise (§0's table, §3's
table). So `reshape.default`'s meta arm reuses `resolve_shape` + the numel check exactly as
`view.default`'s does, and this is not the promise-a-view-where-upstream-copies failure the
note warns about, because meta has no aliasing to get wrong in the first place. Verified
directly: `test_reshape_default_answers_what_upstream_answers_including_the_numel_check`
compares shape AND dtype against upstream's own `reshape` meta kernel across 9 dtype cases
plus wildcards, rank-0, bad-numel and two-wildcard refusals -- all agree.

---

## 4. Tests — `rust/torch_c/pytests/test_metafam.py`

Same method as VOICE4.md §6: one probe script, run as a subprocess against the shim (vendored
tree, `TORCH_USE_RTLD_GLOBAL=1`) and against upstream (`PYTHONPATH` stripped), shape+dtype (or
exception class) recorded per case, then diffed.

15 test functions, ~140 individual probe cases, covering per kernel:

- **0-dim** (`sum([]).dim`, `mean()`, `t()` on a scalar, `permute()` with no dims)
- **empty tensors** (`amax` on a zero-extent dim with and without an explicit `dim=`,
  `any(empty)`, `slice` producing a zero-length result)
- **keepdim** (`sum`, `mean`, `amax` with `keepdim=True` and multi-axis)
- **negative dims** (every op that takes a `dim` argument)
- **dtype promotion** (all 9 dtypes in `DTYPES` -- `f32`/`f64`/`f16`/`bf16`/`i64`/`i32`/`i16`/
  `u8`/`bool` -- through `sum`/`cumsum`/`any`/`amax`/`t`/`slice`; `mean` refuses the
  non-floating ones, which is itself a case)
- **refusals**: `reshape` bad-numel and two-wildcards, `t` rank-3, `permute` duplicate-dim and
  wrong-length, `unsqueeze` out-of-range, `amax` zero-numel with and without `dim=`

One case is deliberately excluded from the strict shim-equals-upstream diff and checked
separately: `amax` on a zero-extent dim WITH `dim=` explicit. Measured, upstream's OWN `meta`
kernel there raises `RuntimeError` while its OWN `cpu` kernel raises `IndexError` for the
identical call -- the same shape of self-disagreement META.md §7.3 already catalogues for
`bitwise_not`/`clamp`/`where` (upstream diverging from itself across devices, not this shim
diverging from upstream). This shim has one door and follows its dense kernel
(`amax_default`, `IndexError`), and `_KNOWN_META_VS_CPU_DIVERGENCE` names the one case this
applies to so it cannot be silently widened to cover a real disagreement later.

`test_the_new_meta_kernels_are_the_meta_half_of_ops_already_implemented` is VOICE4.md §4.1's
move, extended to all 14 op names this round touches: asserts every one is already in
`_aten_implemented()`, so the claim "these are all pre-existing dense ops, zero new ones" is
checked rather than only written down.

---

## 5. Nullification — 8/8 caught

CLAUDE.md §5.5: a verification that cannot fail is not a verification. Each row below is a
DELIBERATE one-line break of the landed code, a full rebuild + reinstall, and a re-run of
`test_metafam.py -k <marker>`, then a restore from the known-good source.

| # | nullification | test that caught it | verdict |
|---|---|---|---|
| 1 | `sum.dim_IntList` returns the input's own dtype instead of `sum_natural_tag` (drops int64 widening) | `test_sum_dim_int_list_answers_what_upstream_answers` | **red** |
| 2 | `mean.dim` returns the input's shape unchanged instead of `reduced_dims(...)` (drops axis removal) | `test_mean_dim_answers_what_upstream_answers_and_refuses_non_floating` | **red** |
| 3 | `amax.default` widens with `sum_natural_tag` instead of preserving dtype | `test_amax_preserves_dtype_and_refuses_the_empty_reductions_dense_does` | **red** |
| 4 | `reshape.default` drops the numel-mismatch check | `test_reshape_default_answers_what_upstream_answers_including_the_numel_check` | **red** |
| 5 | `permute.default` drops the duplicate-dim refusal | `test_permute_default_reorders_and_refuses_what_dense_refuses` | **red** |
| 6 | `squeeze.dim` removes the axis unconditionally (drops the "size != 1 is a no-op" rule) | `test_squeeze_dim_is_a_noop_on_a_non_1_axis` | **red** |
| 7 | `t.default` drops the rank > 2 refusal | `test_t_default_answers_what_upstream_answers_including_the_rank3_refusal` | **red** |
| 8 | `slice.Tensor` drops the step ceil-division (wrong length whenever `step > 1`) | `test_slice_tensor_answers_what_upstream_answers` | **red** |

All 8 were caught by the kernel-level comparison test for that op and nothing else was
needed to catch any of them -- unlike VOICE4.md §6's nullification 4 (a tautological
tolerance assertion), none of these had a structurally blind check standing in front of
them, because every assertion here is a literal equality against upstream's own answer for
the same call, not a restatement of the code under test.

**What was NOT separately nullified**, and why: the eight kernels not listed above
(`mean.default`, `any.default`, `transpose.int`, `unsqueeze.default`, `squeeze.default`, plus
`sum.dim_IntList`'s keepdim branch and `amax`'s two empty-refusal branches specifically) were
exercised by the parametrised probe (§4) and by 3.1's build-time catch, but not each given a
dedicated one-line sabotage-and-rebuild round in this pass, for the plain reason that eight
full rebuild-reinstall-test cycles already used a meaningful share of this round's time
budget and the eight chosen cover every DISTINCT kind of rule in the set (dtype-widening,
dtype-preservation, shape-via-axis-removal, shape-unchanged, numel-validation,
duplicate-detection, no-op-vs-remove, and arithmetic-off-by-one). A future round nullifying
the rest would be extending coverage of the same rule-shapes, not finding a new one.

---

## 6. What is not closed

Per §1's table, the two families named by VOICE4.md are 21 + 12 = 33 ops in META.md §7.4's
count. This round closed 14 names (12 new match arms; `slice.Tensor` and `unsqueeze.default`
already had complex-input arms that untouched). **Left in the reduction family:**

- `max.dim`, `argmax.default`, `topk.default`, `sort.default` — all return an INDEX tensor
  alongside (or instead of) a value tensor, so their meta kernel has to invent an `int64`
  shape rule for the index half too. Not attempted: this is a different shape of problem
  (multi-output) from the single-tensor-out kernels this round closes, and deserved its own
  round rather than being rushed into this one's last hour.

**Left in the view family:**

- `squeeze.dims` (the plural, list-of-axes overload -- `squeeze.dim`/`squeeze.default` are
  closed, `squeeze.dims` is not)
- `narrow.default`, `unfold.default`, `flip.default`, `flatten.using_ints` and others
  META.md §7.4's "12" count implies but does not name individually

**Not attempted at all, named because §2.2 measured it as the actual top of real demand:**

- `aten.embedding.default` — the contraction family, first wall for 5 of 7 real architectures'
  forward pass under meta, ranked ABOVE the reduction/view families in measured priority.
  Out of this round's scope (VOICE4.md named the reduction/view families specifically); flagged
  for the next round rather than folded in here.

**Everything META.md §7.4 already listed under 축약 (contraction, 8), 인덱싱 (indexing, 7),
합성·활성 (composite, 6), 결합·분할 (combine/split, 4), and 그 외 (other, 10)** — untouched,
out of scope for a round titled "close the [reduction and view] families".

GraalVM native image: not attempted, out of this round's scope (per the coordinating
instructions).

---

## 7. Gate

```
PATH="$HOME/.cargo/bin:$PATH" PYTHON=/Volumes/macMini/caches/spike-venv/bin/python \
    bash rust/torch_c/pytests/run.sh
```

```
pytests         1021 ok / 0 fail   (1006 -> 1021, +15 all in test_metafam.py)   EXIT=0
golden          11405/11406 passed, pending 0, ops=302                          PASS
schema          5024/5037 matched                                               PASS
DOCWATCH        903/903 evaluated marker(s) hold                                PASS
cargo test      30/30                                                           PASS
```

Baseline (this worktree, vendor tree freshly built, before this round): 996 ok / 10 FAIL --
the 10 failures were multiprocess (`fed4-*`) and `torch.compile`/`stft` tests contending with
a concurrently-building sibling worktree (`bw-export5`) on the same machine, not this round's
changes; 996 + 10 = 1006 matches the documented baseline count exactly, and none of the 10
failing tests touch meta, reduction, or view code. Not re-verified in isolation given the time
budget; flagged here per CLAUDE.md §5.5 rather than silently assumed innocent.

---

## 8. Added vs fixed vs documented

- **Added** (new capability): 12 meta kernels (`sum.dim_IntList`, `mean.dim`, `mean.default`,
  `cumsum.default`, `any.default`, `amax.default`, `reshape.default`, `t.default`,
  `transpose.int`, `permute.default`, `unsqueeze.default`, `squeeze.dim`, `squeeze.default`,
  `slice.Tensor` -- 14 names, 12 new `match` arms since two ops already had complex-input arms
  under different guards); one shared helper (`reduce_dims_or_all`); `test_metafam.py` (15
  tests, new file).
- **Fixed** (regression this round introduced and caught in itself before landing): the
  `.tensor()` vs `.dims()` bug in §3.1 -- never reached the committed source, caught by the
  first sanity probe.
- **Fixed** (pre-existing test whose boundary needed to move): `test_ops_without_a_meta_kernel_name_themselves`
  in `test_shim.py` named `reshape.default`/`slice.Tensor`/`sum.dim_IntList`/`mean.dim`/
  `t.default`/`permute.default` as ops that must refuse; all six now answer, so the test
  would have failed as a REGRESSION DETECTOR without being wrong about anything real. Moved
  the refusal list to `max.dim`/`argmax`/`topk`/`sort`/`stack`/`squeeze.dims`/`index.Tensor`
  (confirmed still-refusing by direct dispatch call before editing) and added the 14 new
  names to the answering list.
- **Documented**: this file; §2.2's measured priority ranking, which corrects VOICE4.md's
  guessed one; §2.1's confirmation that META.md §7.4 was not stale beyond its own prior
  correction.
- **Not done, and not claimed done**: §6's full list.

<!-- DOCWATCH: op-implemented aten.sum.dim_IntList -->
<!-- DOCWATCH: op-implemented aten.mean.dim -->
<!-- DOCWATCH: op-implemented aten.mean.default -->
<!-- DOCWATCH: op-implemented aten.cumsum.default -->
<!-- DOCWATCH: op-implemented aten.any.default -->
<!-- DOCWATCH: op-implemented aten.amax.default -->
<!-- DOCWATCH: op-implemented aten.reshape.default -->
<!-- DOCWATCH: op-implemented aten.t.default -->
<!-- DOCWATCH: op-implemented aten.transpose.int -->
<!-- DOCWATCH: op-implemented aten.permute.default -->
<!-- DOCWATCH: op-implemented aten.unsqueeze.default -->
<!-- DOCWATCH: op-implemented aten.squeeze.dim -->
<!-- DOCWATCH: op-implemented aten.squeeze.default -->
<!-- DOCWATCH: op-implemented aten.slice.Tensor -->
<!-- DOCWATCH: symbol-in-file rust/torch_c/src/aten.rs reduce_dims_or_all present -->
<!-- DOCWATCH: symbol-in-file rust/torch_c/pytests/test_metafam.py test_sum_dim_int_list_answers_what_upstream_answers present -->
<!-- DOCWATCH: symbol-in-file rust/torch_c/pytests/test_metafam.py test_the_new_meta_kernels_are_the_meta_half_of_ops_already_implemented present -->
<!-- DOCWATCH: count golden_ops_covered ge 302 -->
