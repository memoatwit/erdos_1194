# Witness-split + window-cardinality refinement for r_3(N): architecture, empirical results, and a structural hard pocket

*Working draft - assembled from `WRITEUP_ABSTRACT.md` and `WRITEUP_SECTION_{1..6}.md`.*

---

## Abstract

We describe a reproducible computational framework for upper-bound searches on
`r_3(N)`, the maximum size of a 3-term-arithmetic-progression-free subset of
`[1, N]`. The framework combines a verified lower-bound witness, endpoint
forcing, depth-`d` witness-variable splitting, OEIS A003002 window-cardinality
pruning, and recursive refinement of timed-out subproblems. Applied to the
frontier case `N = 212, K = 44`, it found no feasible `44`-set across millions
of CP-SAT subproblems, supporting but not proving the conjectural value
`r_3(212) = 43`. The main technical findings concern the structural hard
pocket of the residual. A `300`-second recap leaves `45` resistant chunks;
one-hour HiGHS MIP closes none of them; the full eight-hour HiGHS audit
closes `25 / 45` and leaves `20 / 45` with dual bounds still pinned at `0.0`.
A CDCL/SAT re-attack on those `20` LP-paradigm-resistant chunks closes `18`
via conflict-driven clause learning, all of which carry independently
verified DRAT proofs; the remaining `2` chunks (`T1c`) resist all tested
paradigms -- CP-SAT propagation, HiGHS LP-MIP, pure CDCL, and CDCL with a
small window-cardinality subset -- under generous wall caps. We release the
witness, solver scripts, result logs, tiered benchmark instances
(`T1a`, `T1b minus T1c`, `T1c`), the verified DRAT proofs, and a Lean
formal-proof-search encoding of `T1c`, and frame the unit-gap problem
`r_3(212) in {43, 44}` as a target for stronger additive-combinatorial bounds,
custom branch-and-bound, or formal proof-search systems.

# 1. Introduction and background

Let `r_3(N)` denote the maximum size of a subset of `[1, N]` containing no
nontrivial three-term arithmetic progression. Equivalently,

```
  r_3(N) = max {|A| : A ⊆ [1, N], no a < b < c in A satisfy a + c = 2b}.
```

The asymptotic study of `r_3(N)` begins with Roth's theorem \cite{roth-1953}
and continues through Salem--Spencer and Behrend-type lower-bound
constructions \cite{salem-spencer-1942,behrend-1946} and modern
density-increment upper bounds, including work of Bloom--Sisask and
Kelley--Meka \cite{bloom-sisask-2023,kelley-meka-2023}. Those results
describe the large-`N` behavior of progression-free sets. The present paper is
about a different but complementary problem: exact finite computation at the
OEIS A003002 frontier.

OEIS A003002 tabulates exact values of `r_3(N)`. Cariboni's b-file currently
reaches `N = 211`, where `r_3(211) = 43`
\cite{oeis-a003002,cariboni-b003002}. The next natural decision problem is
therefore:

> Does there exist a `44`-element 3-AP-free subset of `[1, 212]`?

We found and independently verified a `43`-element 3-AP-free subset of
`[1, 212]`, so the lower bound `r_3(212) ≥ 43` is settled. The upper-bound
question is whether `r_3(212) ≤ 43`. Since `r_3(211) = 43`, any hypothetical
`44`-set in `[1, 212]` must contain both endpoints `1` and `212`; otherwise it
would translate or restrict to a `44`-set in `[1, 211]`. Thus the target is a
single finite feasibility problem with a strong necessary endpoint condition.

We attacked this feasibility problem computationally using a reproducible
CP-SAT architecture. The model uses Boolean variables `x_i`, one linear
constraint for each 3-term arithmetic progression, the decision equality
`sum_i x_i = 44`, endpoint forcing, reflection symmetry breaking, and
window-cardinality inequalities derived from the known values of `r_3(L)` for
`L ≤ 211`. To make the search tractable, we split the problem by assigning
high-degree variables from a verified `43`-witness, generating a deterministic
depth-`24` chunk space, and then refine residual `UNKNOWN` chunks recursively.

The campaign did not produce a formal proof of `r_3(212) = 43`. It did produce
three concrete outcomes.

First, we observed zero feasible `44`-sets across millions of CP-SAT
subproblems, including broad chunks, recursive refinements, wall-cap
recalibrations, and targeted A/B experiments. This is empirical evidence for
the expected value `r_3(212) = 43`, but it is not a certificate.

Second, we found that OEIS window-cardinality inequalities are essential. On
controlled broad-pass ranges, adding these inequalities reduced the `UNKNOWN`
rate by roughly `28` percentage points and also reduced aggregate solver time.
They are the main successful pruning layer of the campaign.

Third, and most importantly, we identified a structural hard pocket. The
largest retained broad run over `100,000` depth-`24` chunks left `6,071`
`UNKNOWN` chunks. A uniform random `100`-chunk sample of those `6,071`
was passed through a `300`-second recap, leaving `45` resistant survivors.
Re-attacking those `45` chunks with HiGHS, an
LP-relaxation-based MIP solver, closed `0 / 45` in one-hour-per-chunk runs.
A full eight-hour audit later closed `25 / 45`, but left `20 / 45`
`UNKNOWN`, all with dual bound still pinned at `0.0`. A subsequent pure
CDCL/SAT attack closed `18 / 20` of that LP-flat subset, while two chunks
remained `UNKNOWN` even under a 12-hour pure-CDCL cap and a 4-hour
windowed-CDCL diagnostic. Thus the obstruction is not merely a CP-SAT
propagation artifact: the final audited pocket, T1c, isolates two chunks that
resist every solver paradigm tested in this campaign.

The contribution of this paper is therefore methodological rather than a new
exact value of A003002. We provide:

1. A reproducible witness-split plus window-cardinality architecture for exact
   `r_3(N)` upper-bound search.
2. A detailed empirical account of the `N = 212, K = 44` campaign, including
   broad-pass counts, refinement behavior, and solver-time tradeoffs.
3. A characterization of the structural hard pocket. The pocket initially
   appeared invariant under CP-SAT-side tuning and HiGHS; after the CDCL break,
   it remains invariant only on the final two-chunk residual T1c.
4. A tiered benchmark release: the `25` HiGHS-closable T1a chunks, the
   `18` CDCL-closable T1b-minus-T1c chunks, the `2` T1c chunks, the `6,071`
   broad `UNKNOWN` chunks from the `100k` expansion batch, and the generator
   for the full depth-`24` sweep.

For reference, the benchmark tier notation used throughout the paper is:

| Symbol | Meaning |
|---|---|
| T1 | the `45` chunks that survived the `300`-s recap of a random `100`-chunk sample from the `6,071` broad UNKNOWNs |
| T1a | the `25` T1 chunks closed by the full `8`-h HiGHS audit |
| T1b | the `20` T1 chunks left UNKNOWN by the full `8`-h HiGHS audit, all with dual bound `0.0` |
| T1b ∖ T1c | the `18` T1b chunks closed by CDCL and independently verified by DRAT checking |
| T1c | the final two chunks `{40959, 48895}` that resist all tested paradigms |
| T2 | the `6,071` UNKNOWN chunks from the `100k` broad expansion batch |
| T3 | the full `12,582,912`-chunk AP-pruned depth-`24` sweep |

The rest of the paper is organized as follows. §2 describes the
architecture. §3 reports the computational campaign. §4 analyzes
the hard pocket across HiGHS and CDCL. §5 formulates the
remaining open problem as a benchmark release. §6 discusses
transferability, limitations, and what the campaign suggests about finite
`r_3` upper-bound search.

# 2. Architecture

The campaign rests on five components: a decision-form CP-SAT model
of the 3-AP-free subset problem (§2.1), a witness-variable splitting
scheme that produces tractable subproblems (§2.2), a window-cardinality
pruning family derived from OEIS A003002 (§2.3), a recursive refinement
loop for residual `UNKNOWN` chunks (§2.4), and the SLURM-side
engineering that makes the workload reproducible (§2.5). Each
component is independent of the others — any could be replaced by a
stronger variant without disturbing the rest — and together they
define the proof attempt on `r_3(212) ≤ 43`.

## 2.1 Decision-form CP-SAT model

Fix `N ≥ 3` and `K ≥ 3`. The standard CP-SAT encoding of "does there
exist a 3-AP-free subset `A ⊆ [1, N]` with `|A| ≥ K`?" introduces
Boolean variables `x_i ∈ \{0, 1\}` for `i ∈ [1, N]` with `x_i = 1`
iff `i ∈ A`, and adds the constraints

```
  x_a + x_b + x_c ≤ 2     for every 3-AP triple (a, b, c),
  sum_i x_i ≥ K.
```

We adopt the **decision-form** variant in which the second inequality
is replaced by the equality

```
  sum_i x_i = K.
```

The decision-form encoding is tighter for propagation, not for logical
interpretation of `UNKNOWN`: an `UNKNOWN` return on either encoding is still
consistent with both feasibility and infeasibility. The practical advantage of
`sum_i x_i = K` is that CP-SAT and pseudo-Boolean propagators see both the
lower and upper cardinality directions. Branches that would require more than
`K` selected values, or too few remaining unfixed values to reach `K`, can be
cut earlier than in the inequality form. For our purposes (proving the upper
bound `r_3(N) ≤ K - 1`), the equality form is therefore the right primitive.

For `N = 212, K = 44`, the model has `212` Boolean variables and
`11,130` 3-AP triple inequalities. We add the lex symmetry-breaking
constraint

```
  (x_1, x_2, ..., x_N)  ≥_lex  (x_N, x_{N-1}, ..., x_1)
```

to factor out the reflection `i ↦ N + 1 - i`. The opposite orientation would
be equivalent; the implementation uses `≥_lex`. We do not add other
symmetries. After endpoint forcing, reflection is the only order-preserving
symmetry we exploit.

We also apply **endpoint forcing** specific to the `r_3(212)` case.
Since OEIS A003002 records `r_3(211) = 43`, any `44`-element
3-AP-free subset of `[1, 212]` must contain both endpoints `1`
and `212`: if `1` were absent, the set would be a `44`-element
3-AP-free subset of `[2, 212]`, which shifts to `[1, 211]`; if `212`
were absent, it would already lie in `[1, 211]`. Either case contradicts
`r_3(211) = 43`. We add `x_1 = x_{212} = 1` as ground assumptions in
every chunk.

Branching: variable selection by AP-incidence degree (the number of
3-AP triples a variable appears in), value selection `min`, and
`fixed_search` to disable CP-SAT's portfolio search. The first two
target the most-constrained variables first; the third reduces solver-policy
variation across runs, which is necessary for the A/B experiments of §3.2
and §3.5.

## 2.2 Witness-variable splitting

The decision-form model on the full range `[1, 212]` is already at
the limit of single-call CP-SAT solving in reasonable wall time. To
break it into tractable subproblems we use the verified `43`-element
lower-bound witness `A_43 ⊂ [1, 212]` (§2.1, §3.1) as a guide. The
splitting proceeds in three steps.

**Degree ranking.** For each `v ∈ A_43`, compute the AP-incidence
degree `deg(v) = |\{(a, b, c) : v \in \{a, b, c\}, b - a = c - b\}|`.
Sort `A_43` by `deg(v)` in decreasing order. Pick the top
`d = 24` witness values; we refer to this prefix as the **broad split
prefix**.

**Combinatorial enumeration.** For each of the `2^24 = 16,777,216`
IN/OUT assignments of the broad split prefix, instantiate a
**chunk**: the decision-form model with `x_v` fixed to the chosen
value for every `v` in the prefix. A chunk is identified by its
`24`-bit chunk ID.

**AP-prefix pruning.** Many chunks are immediately infeasible at the
3-AP level alone: if the broad split prefix forces three pinned-IN
values that form a 3-AP, the chunk has no feasible completion and
need not be sent to CP-SAT. We perform this check during chunk
emission and skip such chunks. The surviving chunk count for
`N = 212, K = 44` at depth `24` is `12,582,912`, roughly `75%` of
the raw `2^24` count.

The choice `d = 24` is empirical: larger `d` produces more chunks but
each is easier; smaller `d` produces fewer chunks but each is harder.
At `d = 24` the per-chunk solver time at the `60`-s wall cap has a
heavy tail but a tractable median (the broad pass closes `~94%` of
expansion chunks within `60` s — see §3.1), which makes the depth
`24` choice a workable broad layer.

## 2.3 Window-cardinality pruning from OEIS A003002

The 3-AP-free subset problem admits a family of valid inequalities
that are not implied by the 3-AP triple inequalities alone. For
any window `[a, a + L - 1] ⊆ [1, N]` and any length `L` with
`r_3(L) < L`,

```
  sum_{i ∈ [a, a+L-1]}  x_i  ≤  r_3(L).
```

This is valid because `\{i ∈ A : i ∈ [a, a + L - 1]\}` is itself a
3-AP-free subset of an `L`-element interval, hence of size at most
`r_3(L)`. Crucially, the right-hand side `r_3(L)` is *constant* with
respect to `a`, so the family is a single constant per window length,
not a learned bound.

We populate the right-hand sides from the OEIS A003002 b-file
(Cariboni's tabulation, valid for `L ≤ 211`). For `N = 212, K = 44`
we generate window constraints for every available length `L` with
`r_3(L) < min(L, K)` and every `a ∈ \{1, 2, …, 212 - L + 1\}`. The
resulting model contains `22,154` window inequalities.

Empirically the window family is the single most impactful CP-SAT
intervention in the campaign: the controlled A/Bs of §3.2 show a
`~28`-percentage-point reduction in `UNK` rate at the `60`-s wall
cap when window-bounds are enabled. We use it as the default
configuration for every solver call beyond the calibration batch.

## 2.4 Recursive refinement

A chunk that returns `UNKNOWN` at the broad layer is refined by
extending the broad split prefix with the next `m` witness values
(by AP-incidence degree) and re-emitting the resulting `2^m`
subchunks (less AP-prefix pruning) to the solver under a longer
wall cap. The depths and per-step parameters used in the campaign
are:

| Level | Depth | Step size `m` | Per-chunk wall cap |
|---|---:|---:|---:|
| Broad | `24` | — | `60` s |
| L1 | `40` | `+16` | `60` s |
| L2 (tail) | `48` | `+8` | `60` s |
| L3 (level3) | `56` | `+8` | `60` s |
| L4 (level4) | `64` | `+8` | `600` s |

Each level is fed only the `UNKNOWN` residuals of the prior level,
so the work at deeper levels is concentrated on the hard tail. The
expected per-level fan-out `2^m` is mitigated by AP-prefix pruning,
which becomes more aggressive at deeper levels (more pinned-IN
values, more chances for a 3-AP among them). For example, the
Sample-500 L1 stream emits `2,076,105` rows from `500 × 2^16`
nominal descendants, a `~6%` survival rate after pruning.

Refinement is the campaign's primary tool for closing residual
`UNKNOWN` chunks. It reliably closes individual deep chunks
(§3.1 reports `6 / 6` closure at L4). It does not generalize
cheaply to the full `6,071`-chunk expansion residual because the
per-chunk cost grows roughly geometrically with depth.

## 2.5 SLURM engineering

The campaign runs on the UMass Unity SLURM cluster. The workload
pipeline is implemented as a small collection of Python scripts,
each with a single responsibility:

- **`r3_slurm_emit.py`** — generates the chunk-ID list for a given
  `(N, K, split-vars, depth, range)` and emits a SLURM array
  `sbatch` script that fans out the chunks across array tasks. The
  `--chunks-per-task` flag controls the granularity of fan-out.
- **`r3_split_cpsat.py`** — the per-task driver. Reads its slice of
  chunk IDs, instantiates the CP-SAT model for each, runs the solver
  under the per-chunk wall cap, and appends one JSONL row per chunk
  to a shard file.
- **`r3_collect.py`** — merges shard files into the canonical batch
  output. Handles deduplication if a chunk was solved more than
  once (e.g., during retries).
- **`r3_tail_emit.py`** — emits the next-level refinement workload
  from the `UNKNOWN` rows of a parent batch. Supports multi-parent
  inputs (each input JSONL contributing its own parent prefix) and
  templated output naming via a parent-tag regex.
- **`r3_proof_manager.py`** — tracks the proof-state graph across
  levels, identifying which chunks have been closed at which depth
  and which remain open.
- **`r3_verify.py`** — independent triple-enumeration verifier for
  any candidate `K`-element witness.

Two engineering decisions are worth highlighting because they affect
reproducibility:

**Atomic shard renames.** Each per-task driver writes its shard to
a temporary `.tmp` path keyed by the SLURM job and array IDs, and renames it
to `shard.jsonl` on successful completion. A killed or pre-empted
task leaves only the temporary file, which is ignored by the
collector. This pattern prevents partial output from corrupting
downstream collection without requiring any locking.

**Deterministic inputs.** Every chunk ID maps to a fixed prefix assignment,
and every CP-SAT call uses the same solver seed and fixed-search branching.
This is necessary for the lever A/B experiments of §3.5: a "no measurable
effect" claim is only defensible if the baseline arm is reproducible under
the same software stack.

The end-to-end pipeline is driven by `unity_handoff.sh`, which
runs the broad pass, the recap studies, the refinement levels, and
the HiGHS attack as separately resumable phases. A complete
campaign reproduction on a fresh allocation requires the OEIS
b-file, the verified `43`-witness, the Python environment
(OR-Tools, `highspy`, PySAT/CaDiCaL, and `drat-trim`), and a SLURM allocation;
everything else is
generated by the scripts.

# 3. Empirical campaign

This section reports the workload, results, and key A/B tests of the
`r_3(212) ≤ 43` campaign. All experiments were run on the UMass Unity
SLURM cluster against the architecture described in §2. The headline
numbers: millions of CP-SAT subproblems solved, `0` `FEASIBLE`
rows, and a `6.07%` `UNKNOWN` residual in the largest retained broad batch that
motivates the structural analysis in §4.

## 3.1 Chunk-count breakdown

The campaign proceeded in three layers of increasing scope, plus a
recursive-refinement loop on the `UNKNOWN` residuals.

**Verified lower bound.** A `43`-element 3-AP-free subset of `[1, 212]` is
recorded in the repository's witness JSON and re-verified by
`r3_verify.py` against an independent triple-enumeration check. This
witness fixes the campaign's `K = 44` decision-mode target and supplies
the seed for the depth-`24` broad split (§2.2).

**Broad pass at depth `24`, `60`-s wall.** The retained broad-pass logs include
both pre-window and window-bound runs:

| Range | Chunks | INFEASIBLE | UNKNOWN | UNK rate |
|---|---:|---:|---:|---:|
| Calibration, no window bounds, `[575, 1575)` | `1,000` | `799` | `201` | `20.10%` |
| Bounded, no window bounds, `[1575, 11575)` | `10,000` | `6,967` | `3,033` | `30.33%` |
| Bounded, with window bounds, `[1575, 11575)` | `10,000` | `9,835` | `165` | `1.65%` |
| Expansion, with window bounds, `[11575, 111575)` | `100,000` | `93,929` | `6,071` | `6.07%` |

The `20.10%` calibration rate was run *before* window-bounds were enabled
and is included for reference only; once window-cardinality pruning is on
(see §3.2), the residual sits in the `1`–`6%` band depending on the
chunk-ID range.

**Recursive refinement of `UNKNOWN` chunks.** Every chunk timing out at
the broad layer can be refined by extending the witness-pin prefix with the
next-degree split variables and re-solving the resulting subchunks. The number
of emitted rows is not a raw `2^d` fan-out: AP-prefix pruning eliminates many
descendants before a solver call is made. The retained refinement diagnostics
are shown below. The depth labels follow the L1/L2/L3/L4 refinement ladder of
§2.4.

| Stream | Source | Depth added | Rows emitted | INFEASIBLE | UNKNOWN |
|---|---|---:|---:|---:|---:|
| Sample-100 L1 | random sample of `100` broad UNKs | `+16` (to depth `40`) | `299,375` | `299,374` | `1` |
| Sample-100 tail | one Sample-100 residual | `+8` (to depth `48`) | `8` | `8` | `0` |
| Sample-500 L1 | stratified sample of `500` broad UNKs | `+16` (to depth `40`) | `2,076,105` | `2,076,095` | `10` |
| Sample-500 tail8 | `10` Sample-500 residuals | `+8` (to depth `48`) | `76` | `68` | `8` |
| Sample-500 level3 | `8` tail8 residuals | `+8` (to depth `56`) | `8` | `2` | `6` |
| Sample-500 level4 | `6` level3 residuals at `600`-s wall | `+8` (to depth `64`) | `6` | `6` | `0` |

The final Sample-500 level4 cleanup closed all `6` deep residuals within the
`600`-s cap, with a worst-case solver time of `599.74` s — within `0.26` s of
the cap, so this cleanup is at the practical limit of the refinement
strategy at its current parameter settings. Crucially, none of these
levels produced a `FEASIBLE` row.

The `6,071` `UNKNOWN` chunks of the expansion batch were *not* fully
refined by this campaign. Three subsets of them were sampled for
diagnostic experiments: a uniform random `100`-chunk recap study
(§3.2 and §4.2), a structural-mining analysis (§4.1), and the HiGHS
attack of §4.3.

\begin{figure}[t]
\centering
\resizebox{0.96\linewidth}{!}{%
\input{figures/t1_funnel.tex}
}
\caption{Funnel from the retained `100k` broad expansion batch to the final
two-chunk T1c residual. T1 is a `45`-chunk subset produced by recapping a
uniform random `100`-chunk sample of the `6,071` broad UNKNOWN chunks at
`300` seconds.}
\label{fig:t1-funnel}
\end{figure}

## 3.2 The window-cardinality A/B

The single most impactful intervention in the campaign was adding
window-cardinality inequalities derived from the OEIS A003002 b-file.
For every window `[a, a + L - 1] ⊆ [1, 212]` and every length `L` with
`r_3(L) < min(L, K)`, we add `sum_{i ∈ window} x_i ≤ r_3(L)`. For
`N = 212, K = 44` this generates `22,154` inequalities, on top of the
`11,130` 3-AP triple inequalities and the symmetry-breaking lex
constraint.

We measured the effect on three batches of varying size:

| Batch | Chunks | UNK without window-bounds | UNK with window-bounds | Reduction |
|---|---:|---:|---:|---:|
| `[575, 675)` | `100` | `27.00%` | `0.00%` | `−27.0 pp` |
| `[1575, 11575)` | `10,000` | `30.33%` | `1.65%` | `−28.7 pp` |
| `[11575, 111575)` | `100,000` | n/a | `6.07%` | — |

Both controlled A/Bs show a roughly `28`-percentage-point reduction in
`UNK` rate at the `60`-s broad wall cap. The window-bound family is
strictly stronger than the baseline 3-AP family at this problem size. In the
retained logs it also lowered total broad-pass solver time, because many
formerly hard chunks closed early under the extra bounds.

The `[575, 675)` A/B is a `100`-chunk subrange of the calibration range
reported in §3.1; the difference between its `27.00%` no-window `UNK` rate
and the calibration range's `20.10%` reflects the structural non-uniformity of
chunk-ID space rather than a change in model configuration.

However, the `UNK` rate is non-monotone in the chunk-ID range: the small
controlled A/B on `[575, 675)` closes to `0%`, the `10k` bounded batch
sits at `1.65%`, and the `100k` expansion batch sits at `6.07%`. This
indicates that the chunk-ID space is structurally non-uniform — later
chunk IDs (which encode different witness-pin assignments) are harder
in a way that window-bounds do not fully compensate for. The bucket
analysis in §4.1 quantifies this non-uniformity.

## 3.3 Solver configuration and engineering

All CP-SAT calls use the following configuration unless explicitly
overridden in an experiment:

- Model: decision-mode `sum_i x_i = 44`, `11,130` 3-AP linear
  inequalities, `22,154` window-cardinality inequalities, lex
  reflection symmetry break, endpoint forcing `x_1 = x_{212} = 1`.
- Branch strategy: variable selection by AP-incidence degree, value
  selection `min`, `fixed_search` to disable CP-SAT's portfolio.
- Solver: OR-Tools CP-SAT \cite{or-tools}, `8` workers per task, fixed solver seed
  and fixed search parameters, wall cap as noted (most commonly `60`-s
  for broad, `300`-s and `600`-s for recap experiments).

The SLURM emitter, shard collector, tail emitter, and proof-state manager
implement the workload pipeline. Output is
written as line-delimited JSON with one record per chunk; shards are
written to a temporary path and atomically renamed on completion so
that partial output from killed tasks cannot corrupt downstream
collection. The full campaign is reproducible end-to-end via the
`unity_handoff.sh` driver.

## 3.4 Zero FEASIBLE across the campaign

Aggregating across the broad pass, the refinement loop, the recap
studies, the lever experiments of §3.5, and the HiGHS attack of §4.3,
the campaign solved millions of `(N, K, fixed_in, fixed_out)` CP-SAT
subproblems, including prefix-closure work not tabulated above, `45`
HiGHS MIP subproblems, and the CDCL/SAT and proof-producing reruns reported
in §4.3. The number of
subproblems returning `FEASIBLE` is **zero**.

The `FEASIBLE` count is the only signal that would directly disprove
`r_3(212) ≤ 43`; its absence does not constitute a proof of the upper
bound, but it is strong empirical support, especially given that the
campaign forced the endpoints `1` and `212`, which any 44-set must contain by
the known value `r_3(211) = 43`, and then explored a depth-`24` prefix of the
verified 43-witness in the processed chunk ranges. Within the processed
expansion range, a 44-element 3-AP-free subset of `[1, 212]`, if one existed,
would have to lie in the `6,071` unresolved broad `UNKNOWN` chunks (or in
their deeper refinements). Globally, the much larger unprocessed remainder of
the full depth-`24` sweep remains open as well.

## 3.5 Search-tuning levers and their effect sizes

We tested five CP-SAT-side search-tuning levers. The
full lever inventory, including the HiGHS substitution and the
pair-AND Tseitin experiment, is consolidated in §4.4; here we report
only the three CP-SAT-side levers that operate at the broad layer.

| Lever | Mechanism | Bucket | Baseline UNK | Treatment UNK |
|---|---|---|---:|---:|
| Split-vars reorder | Permute the depth-`24` prefix so hot pins (values `{68, 75, 70, 76, 91}`) lead | `[61575, 66575)` | `13.60%` | `12.96%` |
| Wall-cap extension `60s → 300s` | Same model, same prefix, longer per-chunk budget | random `100` from expansion `UNK` | `100.00%` | `45.00%` |
| Recursive deepening | Refine `UNK` to depth `64` at `600`-s cap | `6` L3 residuals | `100.00%` | `0.00%` |

The reorder lever was tested for completeness but is expected to be a
null result on principle: the depth-`24` broad split iterates over the
`2^24` IN/OUT prefix assignments, and within-prefix variable ordering
does not change the set of surviving chunks under AP-prefix pruning
— only the order in which they are emitted to SLURM. The within-noise
result confirms this.

The wall-cap extension lever moves the residual substantially on the
first doubling but exhibits a saturating closure curve under further
extension. The `60s → 120s → 300s` series is analyzed in §4.2; in
brief, the marginal close-rate per additional second of wall drops
sharply past `300`-s, which is why the campaign did not pursue
`600`-s or `1200`-s broad-layer reruns on the full `6,071`-chunk
expansion residual.

The recursive-deepening lever, applied locally to small residual sets,
reliably closes individual deep `UNK` chunks (`6 / 6` at the L4 level
in §3.1). But the levers it implies — picking the next-degree split
variables and re-solving up to `2^8` descendant assignments at a longer wall —
do not
generalize cheaply to the full `6,071`-chunk expansion residual. A
naïve depth-`32` rerun on every expansion `UNK` would emit roughly
`1.5` million subproblems and require an order of magnitude more CPU
time than the original broad pass, with no guarantee of closing the
hard core analyzed in §4.

## 3.6 Compute budget

The retained logs provide measured solver wall time for the main diagnostics.
Since CP-SAT tasks used `8` workers, the worker-hour estimates below multiply
recorded solver-wall seconds by `8`; for HiGHS, the analogous estimate is
`8` threads per one-hour task. These are retained-log estimates, not exact
SLURM accounting totals.

| Layer | Worker-hours | Notes |
|---|---:|---|
| Retained broad logs | `~2,276` | includes the `10k` no-window run, the `10k` window run, the `100k` window run, and the `[575,675)` A/B |
| Sample-100 refinement | `~375` | depth-`40` plus one depth-`48` tail |
| Sample-500 refinement | `~1,978` | depth-`40`, depth-`48`, depth-`56`, and depth-`64` cleanup |
| Recap and worst-bucket A/Bs | `~598` | reorder, `300s` walltime, `120s` recap, `300s` recap |
| HiGHS attack on `45` survivors | `~360` | `1`-h wall, `8` threads per task |
| Full T1 HiGHS long-wall audit | `~2,002` | `45` T1 chunks, `8`-h cap, job `58782313`; estimated from retained `seconds` fields |
| T1b CDCL first run | `~19.8` | `20` single-core tasks, retained JSON row time `71,216.85` seconds |
| T1b proof-producing rerun + T1c diagnostic | `~120` | proof emission + 4-cell T1c grid |
| drat-trim verification | `~61` | jobs `58952708`, `59058393`, and `59383874`; all `18` CDCL-resolved `T1b ∖ T1c` chunks VERIFIED |
| Total retained logs | `~7,850` worker-hours | excludes interactive debugging and logs not retained locally |

The campaign fits comfortably within the `pi_ergezerm_wit_edu` SLURM
allocation on the `cpu` partition. The dominant retained costs are the
`100k` broad expansion, the sample-500 refinement, and the full-T1 long-wall
audit; the CDCL and certificate diagnostics are comparatively cheap. We note
for context that
a full depth-`24` sweep of the `12,582,912` AP-pruned chunks of the
witness-split lattice would require orders of magnitude more worker-hours
under the current architecture. More importantly, it is not justified by the
present evidence: the hard pocket of §4 is the binding obstacle, not simply
broad-layer throughput.

# 4. The structural hard pocket

The headline empirical finding of the campaign is not the absence of a 44-element
3-AP-free subset of `[1, 212]` — which we expected from the OEIS A003002
extrapolation `r_3(212) = 43` — but the existence of a small, robust subset of
broad subproblems that resist every solver paradigm and search lever we threw
at them. We refer to this subset as the *hard pocket*. This section
characterizes it empirically, summarizes the unsuccessful interventions, and
states the resulting open problem.

## 4.1 Empirical signature on the broad population

The `100,000`-chunk window-bound broad batch over chunk-id range
`[11575, 111575)` produced `93,929` `INFEASIBLE` chunks, `6,071` `UNKNOWN`
chunks, and `0` `FEASIBLE` chunks under a `60`-second per-chunk wall cap. The
`6.07%` UNKNOWN rate is non-uniform in two distinct senses.

**Bucket non-uniformity.** Partitioned into twenty `5,000`-chunk buckets, the
UNKNOWN rate varies from `1.64%` to `13.60%`, with the worst bucket
`[61575, 66575)` at `13.60%`. The longest contiguous UNKNOWN run found in this
batch was length `27` at chunk IDs `98277..98303`; many other runs have length
around `15`. These contiguous runs are a strong indication that UNKNOWN status
is driven by joint structural properties of the depth-`24` witness-pin
assignment, not by stochastic solver behavior.

**Pin-OUT enrichment.** For each of the `24` broad-split witness variables we
computed the conditional UNKNOWN rate given that variable's IN/OUT assignment
in the chunk. Five variables — values `68`, `75`, `70`, `76`, `91`, all in the
dense middle cluster `[67, 91]` of the verified `43`-witness — show a strong
asymmetry: their conditional UNKNOWN rate is roughly `2.4%` when pinned IN
and `9.7%` when pinned OUT (Fisher log-odds `+3.5`). The signal is consistent
across the five values. We refer to a chunk in which all five hot pins are
forced OUT as a *middle-out chunk*. Middle-out chunks account for a
disproportionate share of the UNKNOWN tail of the broad batch.

## 4.2 The 300s-resistant tail does not collapse

To test whether the broad-pass UNKNOWNs were merely "slow" rather than
structurally hard, we ran two wall-cap recalibration experiments on a uniform
random sample of `100` UNKNOWN chunks drawn from the `6,071` baseline. The
results show a saturating, not exponential, closure curve:

| Wall cap | INFEASIBLE | UNKNOWN | Close rate over baseline |
|---:|---:|---:|---:|
| 60 s | 0 | 100 | 0% |
| 120 s | 31 | 69 | 31% |
| 300 s | 55 | 45 | 55% |

Going from `60s` to `120s` (2x) closed `31` chunks. Going from `120s` to
`300s` (2.5x further) closed only `24` more. Naïve extrapolation to `600s`
predicts perhaps `10`–`15` additional closures. The hard tail does not vanish
under more time.

We applied the same structural mining procedure (single-pin, pair, and triple
log-odds enrichment relative to a matched `INFEASIBLE` sample) to the `45`
`UNKNOWN` chunks that survived the `300s` cap. The broad pin-OUT signature
weakens substantially. The best high-coverage pair, `[91=OUT, 48=OUT]`, covers
`66.67%` of the survivors with log-odds `+1.226` — a modest effect size, far
from the `+3.5` signal seen on the `6,071`-row population. Top triples have
stronger log-odds but each covers only a handful of cases. Hamming-distance
clustering of survivor `fixed_in` sets shows multiple small clusters rather
than a single dominant niche. We interpret this as evidence that the
`300s`-resistant subproblems share moderate pin-OUT structure but spread
across many distinct sub-pockets of the depth-`24` assignment lattice.

## 4.3 LP-paradigm failure and the CDCL break

The 300s-resistant pocket might in principle be a CP-SAT-specific
phenomenon — an artifact of constraint propagation's inability to exploit
implicit LP structure. To test this, we re-attacked all `45` survivors with
the HiGHS open-source MIP solver \cite{huangfu-hall-2018-highs}, which combines branch-and-bound, LP
relaxation, presolve, cutting planes, and primal heuristics. We used a
one-hour wall cap per chunk, `8` threads per chunk, and the identical
constraint set
(decision-form `sum x_i = 44`, all `11,130` 3-AP triple inequalities, all
`22,154` window-cardinality inequalities, plus the broad chunk's `fixed_in`
and `fixed_out` assignments tightened into variable bounds).

The one-hour result was negative:

The two rows in the following table are not a common-sample comparison: the
HiGHS attack targets precisely the `45` chunks that survived the `300`-s
CP-SAT recap, i.e. the harder subset of the `100` recap inputs.

| Solver | Constraints | Wall cap | Closed (INF) | UNKNOWN | Aggregate solver wall time |
|---|---:|---:|---:|---:|---:|
| CP-SAT, window-bounds | 3-AP + window + symmetry | 300 s | 55 / 100 | 45 / 100 | bounded by ~8.3 wall-h |
| HiGHS, window-bounds | 3-AP + window + endpoint | 3,600 s | **0 / 45** | 45 / 45 | 45.0 wall-h |

Across `162,003` solver-seconds and `3,181,316` explored MIP nodes, HiGHS did
not close a single chunk. No `FEASIBLE` row appeared. The recorded HiGHS dual
bound stayed at its uninformative default value in every task, which is itself
evidence that the LP-relaxation route was not discovering a useful certificate
for these instances.

We then re-attacked all `45` T1 chunks under an extended `8`-hour HiGHS wall,
with LP progress logging enabled. The result is mixed: `25 / 45` chunks closed
`INFEASIBLE`, while `20 / 45` returned `UNKNOWN` at the full cap with dual
bound still pinned at `0.0`. We call this `20`-chunk LP-paradigm-resistant
subset **T1b**. The audit consumed `901,073` solver-seconds and `25,196,448`
MIP nodes.

To test whether T1b is invariant under solver architecture more broadly, we
re-attacked it with a CDCL/SAT solver (CaDiCaL via PySAT
\cite{biere-cadical,pysat-2018}, single-threaded,
`4`-hour wall, encoding restricted to 3-AP triples + cardinality + chunk pins;
no window-cardinality clauses). CDCL closed `18 / 20` chunks `UNSAT`. We call
the surviving `2`-chunk residual **T1c** = `{40959, 48895}`. A T1c diagnostic
at extended wall (`12` h pure CDCL) and with totalizer-encoded window
constraints for lengths `{31, 100, 199}` (`4` h) also returned `UNKNOWN` on
both chunks, so T1c is resistant to all tested paradigms in this campaign.

A proof-producing rerun of the `18` CDCL-UNSAT chunks initially emitted DRAT
proofs for `17` chunks; the remaining chunk, `32735`, required a larger-memory
proof rerun and then also emitted a DRAT proof. Independent `drat-trim`
verification confirmed all `18 / 18` emitted proofs. The final two certificates
were the slowest: `63231` verified in `49,758.11` seconds and `32735` verified
in `80,960.68` seconds under the final `24`-hour verifier pass
\cite{heule-hunt-biere-drat-2014,cruz-filipe-lrat-2017}.

The refined paradigm-invariance picture is therefore: **LP-paradigm methods
(CP-SAT constraint propagation and HiGHS LP-relaxation MIP) fail uniformly on
T1b**, and the CDCL clause-learning paradigm closes `18 / 20` of those chunks,
all of which are independently verified. The genuinely paradigm-invariant
residual is T1c, of size `2`.

## 4.4 Levers tested and their outcomes

For completeness, we record every search-tuning lever we tested on the hard
bucket `[61575, 66575)` or the `300s`-resistant subset. The CP-SAT/MIP-side
tuning levers did not remove the hard pocket; the one qualitative exception is
the CDCL paradigm switch, which closes most of T1b and therefore narrows, rather
than merely tunes, the residual.

| Lever | Mechanism | Result |
|---|---|---|
| Window-cardinality (OEIS A003002) | Add `sum x ≤ r_3(L)` for each window | UNK rate on full `10k` batch: `30.33% → 1.65%`. Strong but plateaus. |
| Split-vars reorder (hot pins first) | Permute the depth-`24` split prefix | `13.60% → 12.96%` on the worst bucket. Noise. |
| Wall-cap extension | `60s → 300s` on the broad pass | Saturating curve, see §4.2. |
| Targeted pair-AND Tseitin propagators | Explicit `pair[a,c] = x[a]∧x[c]` BoolVars on midpoints in `[67, 91]` | Control `67.84s`, treatment `71.75s` on a sampled residual. No effect. |
| Recursive deepening | Refinement at depths `40`, `48`, `56` | All `500` stratified-sample base chunks close, but with a non-trivial tail; the final six level-3 residuals needed up to `599.74s` at the `600s` cap. |
| HiGHS MIP with LP/cut machinery | Replace CP-SAT entirely | `0 / 45` closed at `1` hour; `25 / 45` closed in the full `8`-hour audit, while `20 / 45` retained dual bound `0.0`. |
| Pure CDCL/SAT | Encode T1b as CNF with 3-AP clauses + cardinality + pins, no windows | `18 / 20` HiGHS-flat chunks closed `UNSAT` in 4 hours; `2 / 20` remained `UNKNOWN`; no `SAT` rows. This breaks the strong solver-invariance framing. |

The pair-AND result is worth a closer note. The added constraints are
mathematically redundant with the existing 3-AP triple inequalities — they
encode the same forbidden configurations, just with an explicit Tseitin
variable per pair. The hope was that this would give CP-SAT more
"propagation hooks" in the structural pocket. The negative result is
consistent with the broader picture: the pocket's hardness is not an
encoding issue, it is a search-space issue.

## 4.5 A conjecture about the pocket

We end §4 with a working conjecture about T1c.

CDCL closed `18 / 20` of T1b, refuting the strongest reading of
solver-paradigm invariance for the full `20`-chunk LP-flat subset. The
conjecture below is deliberately narrower: it concerns only the two chunks
that survived the CDCL break.

Each T1c subproblem corresponds to a depth-`24` fixed assignment in which
`(i)` the LP relaxation upper bound on `sum x_i` is at most one above the
decision threshold `K = 44`, leaving no room for LP-based cuts to prove
infeasibility, and `(ii)` the integer infeasibility certificate is too
combinatorially diffuse to fit in the working memory of current CDCL
clause-learning solvers under a `12`-hour wall. The audit of §4.3 bounds the
T1c population at `2` chunks within the `100,000`-chunk window-bound expansion
residual; we do not have a population-level estimate beyond the audited
region.

If this picture is correct, closing T1c requires either (a) a
problem-specific additive-combinatorial upper bound tighter than the OEIS
window-cardinality family, or (b) a custom branch-and-bound or proof-search
system that exploits problem structure neither current general-purpose solver
paradigm captures. Both are framed as open computational problems in §5.

## 4.6 What this means for `r_3(212)`

The combined CP-SAT, HiGHS, and CDCL evidence — `0` `FEASIBLE`/`SAT` rows
across millions of subproblems and all audited hard-pocket diagnostics —
strongly supports the OEIS-conjectured value `r_3(212) = 43`, but the
surviving T1c pocket means we do not have a formal proof of the upper bound
`r_3(212) ≤ 43`. The `6,071` baseline UNKNOWN chunks (and the much larger
unobserved tail of the full `12,582,912`-chunk depth-`24` sweep) remain an
open obstruction. The lower bound `r_3(212) ≥ 43` from the verified witness in
§2 is unaffected. The trivial upper bound `r_3(212) ≤ 44` follows from
monotonicity and OEIS `r_3(211) = 43`, so the gap between our certified bounds
is exactly one.

Closing that final unit gap would require resolving T1c and independently
certifying the entire depth-`24` sweep, including the unprocessed remainder of
the `12,582,912`-chunk T3 lattice. T1c is the sharpest audited open instance,
not necessarily a sufficient stepping stone. We release the hard-pocket
benchmark instances in §5 so specialists can attempt this directly.

# 5. Open problem and benchmark release

The campaign establishes strong empirical support for `r_3(212) = 43`
(§3.4) but leaves a hard pocket that resists both CP-SAT and HiGHS
under every lever we tested (§4). To turn that pocket into a tractable
research target rather than an open compute frontier, this section
states the residual problem cleanly and releases the surviving
instances as a tiered benchmark.

## 5.1 Statement of the open problem

> **Problem (R3-212-UB).** Let `A ⊆ [1, 212]` with `|A| = 44`. Determine
> whether there exists `A` containing no nontrivial 3-term arithmetic
> progression. The verified `43`-element witness in
> `results/N212_K43_witness.json` (§2.1) and the value `r_3(211) = 43`
> from OEIS A003002 jointly imply that any such `A` must contain both
> endpoints `1` and `212`. Equivalently, either exhibit one such `A`
> or certify the infeasibility of the decision problem
> `sum_i x_i = 44` over the `3`-AP constraint family on `[1, 212]`
> with `x_1 = x_{212} = 1`.

A solution to R3-212-UB resolves the unit gap `r_3(212) ∈ \{43, 44\}`
in either direction. Our multi-million-subproblem CP-SAT campaign and
the `45`-instance HiGHS attack returned `0` `FEASIBLE` rows, which is
evidence for the infeasibility branch but not a proof. The
benchmark instances released below pinpoint the subproblems on which
generic combinatorial-optimization solvers currently fail.

## 5.2 Benchmark instance tiers

We release three tiered benchmark sets. Each JSONL row records the chunk ID,
fixed assignments, witness-pin prefix, solver status, and timing data; the
common constraint family (3-AP triples, endpoint forcing, and OEIS window
bounds) is reconstructed by the repository scripts. The tiers form a ladder
from the smallest solver-resistant pocket to the full upper-bound proof.

| Tier | Artifact | Size | Resistance level | Recommended target |
|---|---|---:|---|---|
| T1a | T1a JSONL | `25` chunks | closed by HiGHS at `8`h (dual = `inf`) | reference / regression test |
| T1b ∖ T1c | T1b-minus-T1c JSONL | `18` chunks | LP-paradigm-resistant; closed by CDCL; all `18 / 18` emitted DRAT proofs verified by `drat-trim` | certified CDCL benchmark |
| T1c | T1c JSONL | `2` chunks | resistant to CP-SAT, HiGHS LP-MIP, pure CDCL @ `12`h, and windowed CDCL @ `4`h | minimum-viable proof step |
| T2 | T2 JSONL | `6,071` chunks | survived `60`-s CP-SAT broad pass with window bounds | full closure of the expansion residual |
| T3 | deterministic generator | `12,582,912` chunks | unprocessed remainder of the witness-split lattice | full upper-bound proof |

The concrete filenames are \path{results/N212_K44_t1a25.jsonl},
\path{results/N212_K44_t1b_minus_t1c.jsonl},
\path{results/N212_K44_t1c2.jsonl}, and
\path{results/N212_K44_window100k_unknowns.jsonl}.

Tier T1c is the campaign's sharpest open problem: `2` chunks resistant to
every tested solver paradigm under generous wall caps. A successful T1c closure
either disproves `r_3(212) ≤ 43` (one `FEASIBLE`/`SAT` row suffices, after
witness verification) or eliminates the audited four-paradigm-resistant
residual, leaving the unit gap depending on the unprocessed remainder of T3.

Tier T2 is the canonical "close the campaign at the broad layer"
target: closing all `6,071` chunks of the `100k` expansion batch is
necessary, though not sufficient, for a full upper-bound proof.

Tier T3 is the full upper-bound certificate: closing the entire
depth-`24` AP-pruned sweep. The instance generator (§2.2) emits the
required chunks deterministically from the witness file and the
OEIS b-file; the storage cost of the full sweep is dominated by
output rather than input.

## 5.3 Minimum-viable proof requirements

A formal proof of `r_3(212) ≤ 43` from the released benchmark requires:

1. **Closure of tier T3.** Every chunk in the depth-`24` AP-pruned
   sweep must return `INFEASIBLE` under a verified solver, or one
   chunk must return a `FEASIBLE` `44`-element witness.
2. **Solver verification.** We recommend that any solver used for closure
   either produce machine-checkable proof certificates (DRAT, LRAT, or
   equivalent), or be independently reproduced under a second solver paradigm.
   This is a verification target rather than a condition already met by every
   row of the present campaign; §6.2 records the remaining certificate gaps.
3. **Constraint-set verification.** The `11,130` 3-AP triple
   inequalities, the `22,154` window-cardinality inequalities, and
   the endpoint forcing must be checked against the formal
   definition of `r_3(N)`. The verifier `r3_verify.py` performs
   this check on any candidate witness; an analogous check for the
   constraint generation is included in the repository.

The minimum-viable result short of a full proof is closure of T1c
under a solver paradigm that produces a usable bound certificate
(e.g., LP dual values that improve under cuts, or a CDCL-style
unsatisfiability proof on a SAT encoding of the same constraints).
This would establish that the hard pocket is not solver-architecture
invariant after all, contradicting the conjecture of §4.5.

## 5.4 Approaches we could not test

The following techniques are plausibly stronger than CP-SAT and HiGHS
on this pocket but were outside the scope of our campaign. We flag
them as natural follow-on directions:

- **Fourier-analytic upper bounds.** Behrend-style constructions
  achieve `r_3(N) = N · exp(-c·sqrt(log N))` lower bounds; a
  matching Fourier-analytic upper bound for small `N` would give a
  certificate independent of combinatorial search. The Bloom–Sisask
  framework for `r_3(N) = O(N / (log N)^{1+c})` is asymptotic but
  the underlying density-increment machinery may yield finite-`N`
  bounds tighter than the OEIS window-cardinality family.
- **Multi-window partition bounds.** OEIS A003002 is used here as
  a single-window family `sum_{[a, a+L)} x_i ≤ r_3(L)`. A
  partition-cardinality bound across multiple disjoint windows of
  varying length might cut the LP relaxation more aggressively
  than any single-window family.
- **SAT with proof logging.** A pure CNF encoding has already closed
  `18 / 20` T1b chunks using PySAT/CaDiCaL without OEIS window constraints.
  Follow-up proof-producing runs emitted DRAT proofs for all `18` CDCL-closed
  chunks, and `drat-trim` independently verified all `18 / 18`. The research
  target is now T1c: try longer CDCL walls, different cardinality encodings,
  full-window encodings, or native proof-producing SAT solvers on chunks
  `40959` and `48895`.
- **Lean/formal-proof-search benchmark.** The repository now includes a compact
  Lean 4 / Mathlib 4 formalization \cite{lean4-2021,mathlib4} under `lean/`: shared definitions
  (`R3Base.lean`), the verified `43`-witness statement
  (`R3_212_Witness.lean`), and two AlphaProof-style T1c targets
  (`R3_T1c_40959.lean`, `R3_T1c_48895.lean`) with the expected answer `false`.
  These files are intended as a starting point for an A003002 / `r_3(N)` entry
  in formal-conjecture repositories \cite{formal-conjectures}. Recent AlphaProof Nexus-style workflows
  have resolved Erdős problems of comparable complexity at low per-problem cost
  when a Lean target exists \cite{tsoukalas-alphaproof-nexus-2026}, so T1c is well-shaped for that paradigm.
- **Custom branch-and-bound.** A solver that exploits problem-
  specific symmetries and dominance relations — for instance,
  reflection symmetry after endpoint forcing, or domination of one
  window-bound by another at specific fixed-pin configurations —
  could prune branches that neither CP-SAT nor HiGHS recognize as
  redundant.
- **Symmetric Difference Encoding / Lasserre hierarchy at low
  degree.** A degree-`4` or degree-`6` SDP relaxation of the
  3-AP-free constraint might separate the surviving T1 instances
  from feasibility where the LP relaxation cannot.

We do not advocate for any single direction. The benchmark release
is intended to let specialists pick the technique closest to their
toolkit.

## 5.5 Reproducibility and release

The campaign code, configuration, and result logs are released at
the repository accompanying this preprint. Specifically:

- All Python sources implementing the architecture of §2 are present
  with module-level documentation.
- The SLURM scripts (`submit_*.sbatch`) and the driver
  `unity_handoff.sh` reproduce the full campaign on any
  SLURM-compatible cluster with OR-Tools and `highspy` installed.
- The verified `43`-witness, the OEIS A003002 b-file used for window
  bounds, the broad-pass result logs, the recap residuals, the
  HiGHS attack logs, the T1a/T1b/T1c benchmark JSONLs, verified DRAT
  certificates, LRAT artifacts where emitted with `drat-trim -L`, the Lean T1c
  proof-search targets, environment/version captures for the main solver stack,
  and the scripts needed to generate T3 are all included.
- Existing single-instance entry points (`r3_split_cpsat.py` and
  `r3_highs_attack.py`, and `r3_sat_attack.py`) can rerun any row of T1c,
  T1b, or T2 by chunk ID.

The large solver artifacts are archived on Zenodo at
<https://doi.org/10.5281/zenodo.21413746>. This archive contains the
CNF/DRAT proof artifacts for the `18` CDCL-closed T1b \ T1c chunks,
the available LRAT outputs, verification summaries, SLURM logs, solver
outputs, SHA256 manifests, and reconstruction instructions for split
archives \cite{ergezer-r3-212-artifacts-2026}.

We welcome correspondence on partial results: any solver run that
closes a strict subset of T1 or T2 is a meaningful incremental
contribution, even if the full upper bound remains open.

# 6. Discussion

We close with three observations: what the architecture transfers to,
where it breaks down, and what the campaign suggests about the
broader proof-search problem class for `r_3` upper bounds.

## 6.1 Reusability for adjacent `N`

The five-component architecture of §2 is parametric in `N` and `K`
and depends on two external inputs: a verified `(K - 1)`-element
lower-bound witness for `r_3(N)` and the OEIS A003002 b-file prefix
for window-cardinality pruning at lengths `L ≤ N - 1`. Both inputs
are standard finite data at the current frontier: exact values through
`N = 211` are tabulated by Cariboni/OEIS A003002, and any new run also
requires an explicit verified lower-bound witness at the target size.
We expect the architecture to apply directly to
`N ∈ \{213, …, 220\}` once such witnesses are supplied, with three caveats:

1. The depth of the broad split (`d = 24` for `N = 212`) is empirical
   and likely needs to grow with `N`. The number of feasible-after-pruning
   chunks at depth `d` scales roughly geometrically with the size of the
   witness, so the broad layer for larger `N` will emit more chunks, and
   per-chunk cost will also rise as the number of variables and 3-AP triples
   grows.
2. The `r_3(N)` value drops slowly as `N` grows, so the equality
   `sum x_i = K` becomes harder to refute by simple cardinality
   arguments. We expect the `UNK` rate at the `60`-s wall cap to
   grow with `N`.
3. The endpoint-forcing argument generalizes: if `r_3(N - 1) = K - 1`,
   then any `K`-element 3-AP-free subset of `[1, N]` contains both
   endpoints. This is the only structural input from prior work that
   the architecture exploits; everything else is `N`-uniform.

Within the OEIS A003002 frontier, the architecture is therefore a
drop-in tool for any incremental `r_3(N')` upper-bound attempt, with
the same caveat the present campaign documents: the hard pocket of §4
will likely have an analogue at larger `N`, possibly more severe.

## 6.2 Limitations

The campaign's main limitation is the unresolved hard pocket itself.
Even granting all five CP-SAT levers and the HiGHS substitution, the
architecture cannot close `r_3(212) ≤ 43` without an additional idea.
Section 5 frames this as an open problem; here we record three
narrower limitations of the present implementation:

- **Machine-checkable certificates cover the CDCL-resolved T1b ∖ T1c chunks,
  but not the full campaign.** Follow-up proof-producing runs emitted DRAT
  proofs for all `18` CDCL-resolved T1b ∖ T1c chunks, and independent
  `drat-trim` verification confirmed all `18 / 18`. The `25` HiGHS-closed T1a
  chunks and the `~93,929` broad-pass CP-SAT INFEASIBLE returns remain
  solver-attested rather than third-party-verified; closing this remaining
  gap would require either a SAT re-encoding of each chunk or a verified
  LP-duality-style certificate format we are not aware of in the open MIP
  ecosystem.
- **Compute coverage is incomplete.** The campaign processed
  `100,000` of the `12,582,912` AP-pruned depth-`24` chunks at the
  broad layer, plus refinements on small samples. A full sweep would require
  orders of magnitude more worker-hours under the present parameters and was
  not justified by the available evidence, given the hard-pocket diagnosis.
- **Witness dependence is structural, not adversarial.** The broad
  split is anchored to one specific `43`-witness. A different
  witness would induce a different chunk-ID space and possibly a
  different hard pocket. We did not test whether the hard pocket
  is witness-invariant; if it is not, alternative witnesses might
  bypass the T1c residual of §4.3.
- **The Lean benchmark is not yet upstreamed.** We did not find a public
  A003002 / `r_3(N)` entry in `google-deepmind/formal-conjectures` as of the
  campaign date. The repository includes a Lean 4 formalization of the witness
  and T1c targets, but upstreaming and independent typechecking in that
  ecosystem remain follow-on work.

The third limitation is the most interesting follow-on: a witness-
ensemble version of the broad split, in which the chunk space is
the disjoint union of split-prefixes from multiple distinct
`43`-witnesses, would either reveal an easier alternative covering
of the search space or confirm that the hard pocket is intrinsic
to the constraint family rather than to one witness.

## 6.3 What the campaign suggests about `r_3` upper-bound search

The dominant finding is now more precise than the original CP-SAT/HiGHS
comparison. LP-paradigm methods — CP-SAT-style propagation on the bounded
model and HiGHS LP-MIP — fail uniformly on the `20` T1b chunks with flat dual
bounds, while CDCL closes `18 / 20` of them. The residual T1c set has size
`2` and is the only audited pocket that remains resistant across every tested
paradigm.

Two narrower suggestions follow from the lever inventory of §4.4.
First, the window-cardinality family from OEIS A003002 is doing
nearly all of the work that generic constraint propagation can do;
the `~28`-percentage-point reduction it produces is not matched by
any other intervention at any cost. Second, the levers that *should*
have moved the residual under standard MIP/CP intuition — variable
reordering, pair-AND Tseitin propagators, walltime extension to the
plateau — moved it by less than two percentage points each. The
residual is not lying in wait for a smarter generic search.

The exception is the CDCL paradigm switch (§4.3), which closes `18 / 20` of
T1b. We treat that as a qualitative change of proof system, not another lever
inside the LP-relaxation family.

Combined, these suggest that the most productive next experiment is
not another CP-SAT or MIP variant but either (i) a stronger SAT/proof-search
attack on T1c, (ii) a tighter upper-bound family on `sum x_i`
(Fourier-analytic, multi-window partition, or SDP-derived; §5.4), or
(iii) a custom branch-and-bound that hard-codes the reflection symmetry and
any per-instance dominance relations the generic solvers cannot infer. The
benchmark release of §5 is built to support exactly this kind of follow-on.

We end with the working conjecture of §4.5: T1c corresponds to a
low-dimensional pocket in the depth-`24` assignment lattice along which the LP
relaxation gap is tight and the integer infeasibility certificate, while
present, is not learned by current CDCL encodings under the tested wall caps. A
proof or refutation of this conjecture would be the cleanest mathematical
outcome of the campaign that does not require closing the full unit gap
directly.
