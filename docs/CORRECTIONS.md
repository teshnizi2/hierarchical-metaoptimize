# Corrections — what actually holds

Written after an adversarial review (`REVIEW-hmkhd2.md`) checked the draft against
`results/all_runs.csv` and found several headline claims refuted by controls **in this repo**.
Each item below was re-verified against raw run outputs before being written here.

## 1. The pooling gain is budget-dependent, and the ordering INVERTS

Corrected (meta-gradient-space) pooling, `z'_b = (1-r) sum_j z_j + r z_b`, layerwise m=62:

| arm | 100 epochs (n=3) | 300 epochs (n=2) |
|---|---|---|
| scalar (r=0) | 88.14 | **92.68** |
| plain layerwise (r=1) | **91.35** | 92.01 |
| z-pool r=0.1 | 90.01 (−1.34) | **93.47 (+1.46)** |
| z-pool r=0.05 | — | **93.47 (+1.46)** |
| beta-shrink lam=0.1 | 92.79 (+1.46) | 92.61 (+0.59 best / +0.25 final) |

**At 100 epochs pooling hurts. At 300 epochs pooling wins, and scalar overtakes plain
layerwise.** The optimum in the pooling parameter moves with budget. This is the
bias–variance optimum the literature says is the defensible form of the claim — but it is
*not* the claim the draft made.

Note also that **scalar > plain layerwise at 300 epochs** reproduces the parent paper's
ImageNet observation on CIFAR-10 by lengthening the budget alone. That is a stronger version
of our budget argument than the draft's, and it is free.

## 2. The two "hierarchical" operators are NOT the same method

The draft conflated them. They are different interventions with different effects:

* **beta-shrink** (`HIER=shrink`): contract beta toward the group mean *after* the meta update.
  Helps at 100 ep (+1.46pp), fades by 300 ep (+0.25pp on plateau).
* **z-pool** (`HIER=zpool`): mix the *meta-gradient* before the update. Has exact endpoints
  (verified: sd(beta)=0.000e+00 at r=0). Hurts at 100 ep, wins at 300 ep.

They must be reported separately. Only z-pool has validated endpoints.

## 3. The +1.46pp best-lambda WAS cherry-picked
Max of 7 cells at n=3, spread 0.29pp against per-cell sd 0.08–0.23. Reporting the max of a
sweep as "the" effect is selection bias. The honest statement is the *range* across lambda
(+1.17 to +1.46), and even that is 100-epoch-specific.

Related: "flat over three orders of magnitude" is **operator saturation**, not robustness — a
per-step lambda has half-life <= 693 steps against a 50,000-step run, so every lambda >= 0.001
is fully saturated by the end. The draft presented an artefact as the method's best property.

## 4. Metric hygiene
`best-of-100-epochs` inflates over plateau accuracy by ~0.36pp median — the same order as the
effects being claimed. **Primary metric must be plateau (mean of last 5 epochs) or
epochs-to-target; best-of-run is reportable only alongside, never alone.**

## 5. Claims withdrawn
* The §3 speed table came from **unguarded** runs; with the guard the gain is ~16%, not 19%,
  and ep→85% (10.7 ± 1.2 vs 10.0 ± 0.0) is not resolvable at the ±0.02pp floor.
* §3.1's "scalar fails on 2 of 3 seeds" was already corrected to 1/3 in FINDINGS (0/3 under
  Lion). The draft quoted the superseded number.
* §5's gamma=1 trace-overflow mechanism was **refuted by our own gamma=0.999 control**, which
  failed identically. The overflow is real; the stated cause is not established.

## 6. What survives, and is missing from the draft
* **H4 base-optimizer interaction** — granularity helps under SGDm, null under AdamW. Large,
  multi-seed, unaffected by any of the above.
* **The budget inversion** (§1 here) — now the strongest result in the project.
* Results the routine produced that the draft never mentioned: a 53.1% sign-agreement
  measurement, a 4.4pp aggregation-order effect, and M1 additive reaching 93.46 at n=5.
  These need checking and, if they hold, they belong in the paper.

## 7. Process failure to avoid repeating
The refuting controls **had already completed** when the draft was written; they were produced
by the hourly routine and never reviewed. Writing prose from remembered results instead of from
`results/all_runs.csv` is what caused this. **Re-derive every table from the CSV at write time.**

---

## 8. The three "unreviewed" results, now verified — two are major

### 8a. M1 additive has a genuine interior optimum (plateau metric, n=5–10)

> **SUPERSEDED BY §10.** The table below pools two meta-optimizers into the same
> cells and its per-cell numbers and n are wrong. The interior optimum itself
> survives — see §10 for the corrected, stratified table.

| r | plateau | n |
|---|---|---|
| 0 (= scalar) | 92.15 | 5 |
| 0.03 | 92.14 | 8 |
| **0.05** | **93.06** | 7 |
| **0.07** | **93.22** | 5 |
| 0.1 | 92.28 | 10 |
| 0.2 | 91.39 | 3 |
| 0.3 | 90.96 | 3 |

A clean inverted-U peaking at r ≈ 0.05–0.07, **+1.07pp over r=0**, measured on plateau rather
than best-of-run, at n=5–7. This is the bias–variance optimum in partial pooling that the
project set out to find, and it is the best-supported positive result we have.

### 8b. The i.i.d. / sqrt(N) noise model is REFUTED by direct measurement

The premise behind "finer granularity is noisier" is that per-coordinate meta-gradients are
near-independent, so pooling N of them shrinks drift as 1/sqrt(N). The probe measures the
premise directly:

> **53.1% of all 11,173,962 per-weight meta-gradients agree on sign.**
> Independence would give 50.0000 ± 0.0015%.

Predicted log-log slope of drift vs N: **−0.500**. Measured: **−0.113**.

The signs are strongly positively correlated, so a pooled estimate does not average toward zero —
it converges to a population bias. **Drift is governed by how much the coordinates agree, which
is a property of the partition, not by N through a sampling-noise channel.** This is the
within-block correlation the prior-art sweep identified as the one unclaimed empirical
contribution available here, and it is now measured rather than assumed.

### 8c. The alpha0 confound is quantified, and it accounts for the short-budget orderings

Pooled layerwise is 17.6pp *behind* scalar at 20 epochs and 4.5pp *ahead* at 100. The 20-epoch
ordering is fully explained by startup cost: beta must climb 6.9 log units from ln(1e-6) before
alpha is useful, and the arms escape at different rates —

| arm | epochs merely to reach a useful alpha |
|---|---|
| scalar | 13.8 |
| 6-block | 14.0 |
| layerwise | 17.3 |
| nodewise | 25.1 |

**A substantial part of what earlier tables called "the granularity effect" at short budgets is
the arms escaping a deliberately crippled initialisation at different rates.** Every
short-budget comparison at alpha0 = 1e-6 must be read with this in mind, and the alpha0 control
runs are the correct basis for any steady-state claim.

## 9. Fixes applied this round
* `analysis/aggregate.py` now emits **plateau** (mean of last 5 epochs) as primary, plus
  `ep_to_85/88/90` and guard/hier/lambda/eta_ratio provenance. Measured: best-of-run inflates
  over plateau by **0.37pp median** across 356 runs — the same order as the effects claimed.
* **Non-meta baseline launched** — plain AdamW at 4 fixed learning rates x 2 seeds. Across the
  first 275 runs there was *not one* non-meta-learned optimiser to compare against; a reviewer
  would have asked immediately.
* **Seeds raised to 5** on the 300-epoch headline cells (plain / zpool r=0.1 / scalar).

---

## 10. §8a pooled two meta-optimizers; the optimum survives, the table did not

Re-deriving §8a from `results/all_runs.csv` (rule 1) showed its cells were not homogeneous.
Two different run families were being averaged together:

* `ad-l-*` — `--alg-meta Lion`, account `s5014158`
* `adg-A-*` — `--alg-meta Adam`, account `salehkaleybars`

The Adam family sits ~1.3pp lower at matched `r`. The pooling was **unbalanced across the
sweep**: r=0.05 and r=0.07 contain Lion runs only, while r=0.03 and r=0.1 mix in Adam runs.
That pulled the shoulder cells down and the peak cells not at all — i.e. the pooling
manufactured part of the contrast it was being used to demonstrate. This is the same
failure mode as §3 (reporting a heterogeneous max), one level further down.

### The corrected table — one meta-optimizer, one account

`hier=additive`, `granularity=layerwise`, 100 epochs, plateau (mean of last 20 epochs),
`superseded==0`, `--alg-meta Lion`, account `s5014158`:

| r | n | plateau | sd | Δ vs r=0 |
|---|---|---|---|---|
| 0 | 3 | 92.20 | 0.04 | +0.00 |
| 0.03 | 5 | 92.64 | 0.16 | +0.44 |
| 0.05 | 5 | 93.09 | 0.10 | +0.89 |
| **0.07** | **5** | **93.22** | **0.14** | **+1.02** |
| 0.1 | 5 | 92.63 | 0.21 | +0.43 |
| 0.2 | 3 | 91.39 | 0.14 | −0.81 |
| 0.3 | 3 | 90.96 | 0.08 | −1.24 |

**The interior optimum is real and is now cleaner than the pooled version.** Stratifying
turns the ragged 92.15 / 92.14 / 93.06 opening of the old table into a monotone rise to a
peak at r=0.07 and a monotone fall after it. The effect at the peak is +1.02pp against a
per-cell sd of 0.04–0.21, so it is 5–25x the noise. What changed is the shape's credibility,
not its existence.

Corrections to the individual cells of §8a: r=0.03 was 92.14, is **92.64**; r=0.1 was 92.28,
is **92.63**; r=0 was 92.15 at n=5, is **92.20 at n=3**; r=0.05 was 93.06 at n=7, is **93.09
at n=5**. The inflated n came from counting the pooled Adam runs.

### The generalisation claim is not yet testable — meta-optimizer is confounded with account

Every Lion additive run is on `s5014158`; every Adam additive run is on `salehkaleybars`. The
1.3pp gap is therefore **not attributable to the meta-optimizer** — it could equally be a
difference in the two accounts' code or environment state. Nothing about "the optimum is
Lion-specific" can be read off the current data.

Worse, the Adam arm has **no r=0 anchor at all**, so it has no within-arm baseline and cannot
show an interior optimum even in principle. That is why its Δ column is empty above.

**Launched this round to break it:** `amx-r{0,05,07}-s{0..4}` — 15 jobs, Adam meta, layerwise,
100 epochs, n=5, submitted on `s5014158`, the *same* account as the Lion sweep and identical
to it in every argument except `--alg-meta`. Reading the result:

* rises ~92.2 → ~93.2 → the optimum generalises across meta-optimizers, and the old 1.3pp gap
  was the account, not the method
* stays ~1.3pp low but still inverted-U → the optimum generalises; the offset is the
  meta-optimizer
* flat → the optimum is Lion-specific, and the headline result needs that caveat in the paper

Any of the three is publishable; the current state, which cannot distinguish them, is not.

## 11. Two aggregator bugs found and fixed

**`account` was wrong on every row.** It was inferred from `"/home/s5014158" in path`, which
holds on the cluster but not in the local backup, where alice2's runs sit under `runs_alice2/`.
All 428 rows read `salehkaleybars`, so *any* per-account analysis was void — including the
confound check in §10, which is why that confound went unnoticed until now. It now reads the
recorded `--save-directory`, which travels with the artefact, and falls back to the path.
Corrected split: 263 `salehkaleybars` / 165 `s5014158`.

**`run` is not a unique key.** A resubmission reuses `--run-name`, so a finished run and an
in-flight one can share a name; any analysis keying a dict on `run` silently keeps whichever
was parsed last. Three completed 100-epoch alpha0 controls (`a0-{scal,layer,blk6}-1e4_s0`,
plateau 91.75 / 92.05 / 91.75) were being shadowed by 30-epoch reruns this way — the partial
value would have replaced the real one in any downstream table. The CSV now carries
`dup_group` and `superseded`, aggregate.py warns on stderr, and **every analysis must filter
`superseded == 0`**.

### Housekeeping in the same pass
* **12 redundant jobs cancelled** on `s5014158`. The whole queued `a0-*` batch (2 alpha0
  values x 3 granularities x 2 seeds) re-ran configurations that had *already completed* at
  100/100 epochs; each was verified against its finished counterpart before cancelling
  (argument lists identical up to flag order, ENV lines identical). They were consuming 4
  running GPU slots and would have created 12 further run-name collisions.
* **13 pending jobs widened** on `salehkaleybars`. A blanket widen fails on the 6-hour
  300-epoch arms with "Requested time limit is invalid" — `gpu-short` caps at 4h. Those 9 go
  to the four 7-day GPU partitions only; `bin/widen_long.sh` now branches on the job's own
  time limit.

### A documentation mismatch, resolved in favour of the code
`plateau` in the CSV is the mean of the **last 20 epochs**, but §4 and §9 of this document,
`PLAN.md` and `PLAN-appendix-research.md` all describe it as the mean of the last 5. The
20-epoch window is what every number in this repo actually is. Checked rather than assumed:
recomputing the whole M1 sweep at k=5 moves no cell by more than 0.15pp and leaves the peak at
r=0.07, so no conclusion depends on the choice — but **the prose is what is wrong, not the
code**, and it should be corrected to "last 20 epochs" wherever it appears.

## 12. The sign-agreement headline is measured in the regime Rule 5 warns about (cycle 18)

`runs/bdrift3/p3-*` — cycle 7's own α₀=1e-3 control for the β-drift/sign-agreement probe — had
been sitting in this repo unreduced since it ran. Reduced now with the published methodology
(drift = |Δβ̄|/step over steps 1000–7500, `frac_neg` averaged over the same window).

**What survives.** The √N noise model predicts a log-log drift-vs-N slope of −0.500. Measured
**−0.110 at α₀=1e-6 and −0.136 at α₀=1e-3**. The refutation holds in *both* regimes and is now
robust to the α₀ confound rather than merely asserted against it. This remains the campaign's
most defensible result.

**What must be qualified.** Weightwise sign-agreement (excess over a balanced split,
|2·frac_neg − 1|) is **6.20% at α₀=1e-6 and 0.38% at α₀=1e-3 — a 16× collapse.** Much of the
"coordinates strongly agree" reading is the shared climb out of a 7-log-unit hole: coordinates
being driven the same way by a bad init agree trivially. At steady state the excess is 0.38%,
which over 11.17M coordinates is still **+12.7σ** from independence — genuinely non-independent,
but a *small* bias, not a strong one.

> **The "53.1% of 11.17M meta-gradients agree on sign" number is an α₀=1e-6 measurement and
> must never be quoted without that qualifier.** At the steady-state control it is 50.19%.

**What is withdrawn.** Cycle 6 predicted and cycle 7 marked **CONFIRMED** that "drift falls
monotonically with N". At α₀=1e-3 it does not: scalar 3.04e-4 > nodewise 1.84e-4 > layerwise
1.57e-4 > 6-block 1.03e-4 > weightwise 1.70e-5. Monotonicity is an α₀=1e-6 artefact; only the
endpoints (scalar highest, weightwise ~18× lower) survive at both α₀.

**Also corrected:** ResNet18 `nodewise` N has been recorded as "~4,800" since cycle 7. Measured
by direct instantiation it is **14,420**. Refitting the slope with the corrected N moves it from
−0.1130 to −0.1095 — immaterial, but the wrong N should not be re-quoted. Full N ladder for all
four architectures is in FINDINGS cycle 18 §2.

**Process note (Rule 1, third occurrence).** The refuting artefact was already in the repo. The
first two occurrences were controls that sat unread; this one was a control that *was
deliberately submitted for exactly this purpose* in cycle 7, completed, and then was never
reduced. Reducing every probe dir that exists should precede submitting new ones.

---

## 13. The M1 pooling baseline was the wrong endpoint (cycle 20)

**What was wrong.** Cycles 16–19 quoted the M1 additive-pooling gain against `r=0`, describing
it as the no-pooling control — e.g. "interior optimum r ≈ 0.05–0.07, plateau 93.06–93.22 vs
**92.15 at r=0**".

**What the code actually does.** `patches/HF_patched.py::_apply_hier`, additive branch:

```
d    = beta - beta_prev
dm   = d.mean()
beta = beta_prev + dm + r*(d - dm)
```

`r` is the **retention of the group-specific part of the update**. At `r=1` the expression
telescopes to `beta_prev + d = beta`, the exact identity — **plain layerwise**. At `r=0` every
group takes the mean update — **full pooling**. So `r=0` is the *maximally pooled* extreme and
was being used as the *un*-pooled baseline.

**Structural verification** (not asserted from the algebra — measured, per Rule 4).
ResNet18/CIFAR-10, α₀=1e-6, plateau, `epochs_done>=100`:

| arm | n | plateau |
|---|---|---|
| additive r=1 | 3 | 90.863 ±0.063 |
| plain layerwise, `HIER` unset | 47 | 90.891 ±0.492 |

0.028pp apart — inside the ±0.02–0.05pp reproduction band.

**Effect on the claims.** No run changed and no measurement was wrong; only the baseline was
misnamed. The corrected headline is **larger**, not smaller:

| | old phrasing | corrected |
|---|---|---|
| ResNet18/C10, α₀=1e-6, r*=0.06 | +1.07pp "vs r=0" | **+2.40pp vs no pooling (r=1)** |
| | | (+1.07pp vs full pooling, r=0) |

The curve is unimodal with **both** endpoints now measured, which is a better result than the
one it replaces. What it costs is transferability: the ResNet10 ladder, read correctly, is
+1.00pp rather than the +8.7pp that "vs r=0" implied, and on CIFAR-100 the same r is
**−43.7pp**.

**Process note (Rule 4, second occurrence).** The first occurrence was a pooling identity that
was never checked at all. This one is worse: a check *existed* — `drift_extract.py` printed a
`spread` column advertised as verifying that pooled arms carry one step size — but it read
`beta_true_max − beta_true_min`, two probe fields that are written **identically on every arm**.
It reported 0.0000 by construction and could never have failed. A verification that cannot fail
is worse than no verification, because it is recorded as evidence. Replaced by `sd_beta` in
`bin/drift_extract2.py`.

---

## 10. The baseline comparison was NOT fair, and three experiments now fix it

Reported "MetaOptimize loses to tuned AdamW+cosine by 1.41pp." That comparison had three
structural flaws, all favouring the baseline. None invalidate the measurement; all mean it was
the wrong measurement to draw a verdict from.

### Flaw 1 — budgets were not matched
Meta arms were compared at 100 epochs against a baseline measured only at 100 epochs, while the
300-epoch meta data (93.47) was compared against the *100-epoch* baseline (94.24). MetaOptimize
optimises a **discounted sum of future losses with gamma -> 1**; it is built for the long run, so
100 epochs is the regime least favourable to it. The cosine baseline additionally **knows the
horizon** (`COS_TOTAL`) and anneals onto it — information MetaOptimize is deliberately denied.
**Running:** baseline vs best meta config at 300 and 600 epochs, budget-matched cosine, n=3.

### Flaw 2 — search budgets were not matched
The baseline consumed a 4-point LR sweep; each meta arm got a single run. **MetaOptimize's
actual claim is that it needs no tuning**, so comparing its one run against the best of four is
rigged on precisely the axis the method exists to address. The honest comparison is *expected
accuracy per unit of total compute*: for the baseline that is best-of-K LRs, for MetaOptimize it
is the typical (not best) result over K seeds.
**Running:** cosine LR sweep over 7 decades x 3 seeds, to characterise what an *untuned* choice
actually costs.

### Flaw 3 — we never ran the paper's own setup
All our runs enable augmentation. The parent paper never mentions augmentation and its released
code has none. Augmentation was the scientifically correct call (unaugmented ResNet-18 memorises
CIFAR-10 in epoch 1), but it means **we have never reproduced their claim in their setting** and
cannot answer a reviewer who asks whether it holds there. Their evidence is Fig. 1 *learning
curves*, so the comparison must be on convergence, not the endpoint.
**Running:** paper config (AdamW base + Adam meta, alpha0=1e-6, eta=1e-3, gamma=1), **AUGMENT=0**,
scalar vs 6-block vs layerwise, n=3.

### Standing rule
**Never report a comparison until budget, search budget, and setup are all matched — or until
each mismatch is stated in the same breath as the number.** Two of these three flaws were caught
by the operator, not by us.

---

## 14. The config key omitted `granularity`, and a "logging gap" was invented to explain it (cycle 25)

**What was wrong.** Cycle 24 (FINDINGS 24.1) recorded, as the campaign's "highest-value
integrity item":

> **Unresolved anomaly:** `ad-l` (92.626, n=5) and `adg-b` (91.598, n=3) agree on *every*
> recorded field yet differ by **1.03pp**, ~50x the +-0.02pp reproduction tolerance. Something
> that determines a 1pp effect is not being logged.

**What is true.** They do not agree on every recorded field. They differ in
`--stepsize-groups` — `layerwise` vs `resnet18_blocks` — which is in the ARGS line of both
`.out` files and in the `granularity` column of both CSV rows. The aggregator was correct.
Cycle 24's *analysis* grouped by an 8-field key that left out `granularity`, the single most
important field in the project, and so pooled two granularities into one cell.

**Effect on the claims.** The r=0.1 cell of the M1 ladder goes from 92.240 +-0.556 (n=8,
two granularities) to **92.626 +-0.214 (n=5, layerwise only)** — sd down 2.6x. The peak cells
(r=0.05/0.06/0.07) contained no 6-block runs and are unchanged. The curve is now monotone on
both sides of r=0.06. Nothing about the interior optimum changes; one ragged cell becomes clean.

Discharged: 24.1's standing caveat that "the r=0.1 cell stays heterogeneous until this is found."

**Rule amended.** The canonical config key is **nine** fields:
`network, dataset, batch_size, base, meta, meta_stepsize, alpha0, gamma, augment, beta_clip,
epochs_requested, granularity, hier, eta_ratio, lam` — and `granularity` is never optional.

**Process note.** The failure mode is new and worth naming separately from Rule 1. Rule 1 says
re-derive numbers from the CSV; this *was* re-derived from the CSV. The defect was in the
**grouping**, and the symptom — an unexplained gap between two supposedly-identical cells — was
attributed to the instrument (a missing log field) rather than to the analysis. **When two cells
that "should" match do not, check the grouping before concluding the data is incomplete.** The
raw artefacts answered it in one diff.

---

## 15. `_zpool`'s pooling parameter is not comparable across granularities (cycle 25)

**What was wrong.** The zpool sweep has been read across granularities as though its `r` meant
the same thing at each — e.g. comparing the layerwise and weightwise r-curves directly.

**What the code does.**

```
_zpool:            z'_b = (1-r)*SUM(z)  + r*z_b          <- SUM, scales with m
_zmpool:           z'_b = (1-r)*MEAN(z) + r*z_b          <- MEAN, m-invariant
_apply_hier (M1):  beta_prev + MEAN(d) + r*(d - MEAN(d)) <- MEAN, m-invariant
```

`_zpool`'s pooled term scales with the group count m, so the scalar->plain transition is
compressed against r=1 by a factor of m. Its **endpoints remain exact** and are verified
(FINDINGS 25.4: r=0 reproduces plain scalar to 0.009-0.032pp, r=1 reproduces plain to
0.099-0.149pp, at both layerwise and weightwise). Only the path between them is m-dependent.

**Consequence.** At weightwise (m=11.17M) the region equivalent to layerwise's interesting
r in [0.9, 1] sits at `1-r ~ 5e-8`, **below float32 eps (1.19e-7)**. `_zpool` cannot express
weak pooling at weightwise. The entire 11.13pp weightwise transition is squeezed into the two
measured cells r=0.99 and r=1, and its optimum is unlocated.

**What survives.** M1 (`additive`) and `_zmpool` are both mean-based, so *their* `r` is
comparable across granularities. Every cross-granularity pooling claim must use one of those
two operators, never `_zpool`. FINDINGS 25.3 (M1) and the `zmg-*` batch (zmpool) are built on
that basis.

## 16. `block_sizes.json` reports the wrong coordinate count for nodewise (cycle 26)

`HF._probe_init` builds `n_b` with an if/elif over `layerwise` / `scalar` / `blockwise` and
falls through to `nb = self.param_numels` for **everything else** — which lumps nodewise in
with weightwise. So for a nodewise arm `block_sizes.json` records **11,173,962** coordinates
when the arm actually has **14,420** nodes.

Nothing in the record flags this, and the wrong number is silently plausible. Any significance
statement about nodewise sign-agreement computed against `block_sizes.json` overstates its
z-score by `sqrt(11173962/14420)` = **27.8x**.

**The count is recoverable and must be recovered, not trusted.** `frac_neg` is a rational
`k/n_tot`, so the smallest denominator consistent with the observed fractions IS `n_tot`.
Verified against independently recorded counts:

| arm | inferred `n_tot` | independently recorded |
|---|---|---|
| `probe_sig_resnet18_blocks_s0` | 6 | 6 blocks |
| `probe_sig_layerwise_s0` | 62 | 62 layers |
| `probe_sig_nodewise_s0` | **14,420** | 14,420 nodes (25.3) |
| `probe_sig_weightwise_s0` | 11,173,962 | 11.17M params (25.3) |
| `p5-r34-w` | 21,282,122 | ResNet34 = 21.3M |

All five match. `bin/agree2.py` infers `n_tot` this way and never reads `block_sizes.json`.

**Standing rule:** a probe field that was *derived* at write time (group counts, block sizes,
`beta_true_min/max`) is a claim, not a measurement. Re-derive it from the raw record before
using it in a significance statement. This is the same defect class as `drift_extract.py`'s
`spread` column — a verification that could not fail — and as the `collapsed` column, which is
`0` on every row.

## 17. `drift/step` is censored by Lion's sign update, and two published slopes sit on the ceiling (cycle 26)

The meta-optimizer is **Lion**, whose update is `sign(...) * lr`. So `|d beta|` per step is
EXACTLY the meta-stepsize (1e-3), and therefore

```
drift/step  <=  meta_stepsize            (hard ceiling, not an empirical bound)
drift/step / meta_stepsize  =  net temporal sign-consistency of the meta-gradient
```

`p4-r10-scal` and `p4-c100-scal` both read **exactly 1.000e-03** — pinned at the ceiling, i.e.
the scalar step size moved in one direction on every single step. A censored point cannot
carry a regression, but both were included in the published log-log fits.

Refitting the `p4scale` drift-vs-group-size slopes without the saturated arm:

| setting | published (all 4) | unsaturated | R^2 all 4 -> unsat |
|---|---|---|---|
| ResNet10 / CIFAR-10 | +0.238 | **+0.177** | 0.68 -> 0.41 |
| ResNet18 / CIFAR-100 | +0.290 | **+0.150** | 0.36 -> **0.08** |
| ResNet34 / CIFAR-10 | +0.205 | +0.205 (none saturated) | 0.70 -> 0.70 |

**What survives:** the sqrt(N) refutation. The slope is POSITIVE in 6/6 fits across two
alpha0 (`p4scale` 1e-3, `p5scale` 1e-6) and three settings, where the model requires -0.500.
A sign inversion that robust does not depend on one censored point.

**What does not survive:** the slope magnitudes as point values, and the CIFAR-100 / a0=1e-3
cell as evidence of a *trend* at all — its R^2 falls to 0.08 once the ceiling point is
dropped. Quote the slopes as a positive range, and normalise drift by the meta-stepsize.

## 18. `z_mean` is not the meta-gradient whose signs make `frac_neg` (cycle 28)

**What was nearly claimed.** `gate1` (alice, Aug 18) is field-for-field identical in its ARGS
line to `mx/probe_sig_*`, the series 26.3's published sign-agreement ladder is built from —
same base, meta, momenta, weight decay, meta-stepsize, alpha0, network, dataset, batch size,
epochs, seeds. It had never been reduced. The obvious move was to reduce it and report it as
an independent n=3 replication of the published ladder.

**Why that is wrong.** `gate1` predates the probe's `frac_neg`/`frac_zero` fields. Its records
carry `beta`, `z_mean`, `z_std`, `snr` only. A reducer built to recover agreement from
`sign(z_mean)` (`analysis/agree_legacy.py`) was validated against `mx`, which carries BOTH
formats — same records, same window, same code path — and disagreed:

| rung | `frac_neg` (agree2.py) | `z_mean` (agree_legacy.py) | delta |
|---|---|---|---|
| resnet18_blocks (m=6) | 70.87±0.80 | 63.70±0.78 | **−7.17** |
| layerwise (m=62) | 53.26±0.19 | 54.77±1.26 | +1.51 |

`z_mean` is a per-TENSOR running mean: it has 62 entries on EVERY arm, including the
14,420-node and 11,173,962-weight arms, whose true coordinate counts `agree2.py` infers from
the `frac_neg` denominators. It is a different quantity at a different resolution, and its
disagreement is 7pp — roughly the size of the whole m=6-to-m=62 fall the ladder reports.

**The rule.** Any probe directory whose records lack `frac_zero` is on the LEGACY statistic.
Its numbers may be compared to other legacy numbers and to nothing else. `agree_legacy.py`
prints the same column layout as `agree2.py` on purpose, which makes the two easy to paste
into one table — do not. This is the second time a probe field has looked interchangeable and
was not (see CORRECTIONS 16 on `block_sizes.json`'s `n_b`).

**What survives.** Within the legacy statistic, read consistently, `gate1` reproduces `mx` to
0.055pp (m=6) and 0.083pp (m=62) — a genuine cross-batch reproducibility result (28.3) — and
`gate2` vs `gate1` is a like-for-like base-optimizer contrast (28.4). Neither may be placed on
26.3's table.

**Also recorded:** `gate3` (SGDm base, meta Adam, no beta clip) is DIVERGENT — `sd_beta` 20.5
in log space against `mx`'s 2.39 — and its `z_mean` agreement pins at exactly 100.0000% on all
three seeds at m=6. It is excluded from every agreement claim rather than reported as a low
outlier.

## 19. `agree2.py` censored every coordinate count above 20,000,000 (cycle 29)

`infer_ntot` recovered the coordinate count as the denominator of the observed `frac_neg`
rationals:

```python
best = max(best, Fraction(v).limit_denominator(20_000_000).denominator)
```

**The 20,000,000 is the tool's ceiling, not the model's.** Any arm with more coordinates than
that is reported AT the ceiling, silently.

Measured this cycle on `p7-*`: ResNet34/weightwise has **21,282,122** coordinates — summed
directly from `block_sizes.json`'s `n_b` over its 110 tensors, which for *weightwise* is the
one thing that field is reliable for, since weightwise groups ARE the parameters (contrast
CORRECTIONS 16, where the same field is wrong by 775x for nodewise). `agree2.py` reported
exactly `20,000,000`.

**What it corrupted.** The independence null is `E = 0.5 + sqrt(2/pi) / (2 sqrt(n))`, so a
censored `n` gives a null that is too HIGH and an excess-over-null that is too LOW:

| | reported n | null% | R34/weightwise excess (s1, s2) |
|---|---|---|---|
| before | 20,000,000 | 50.00892 | 0.0029, 0.0038 |
| after | 21,282,122 | 50.00865 | 0.0033, 0.0052 |

~10–35% relative on the affected cells. **No sign flipped and no ordering changed**, so
29.1's ladder is unaffected in shape — but the numbers published before this cycle for any
arm above 20M coordinates were wrong.

**Fixed** by raising the cap to `100_000_000` (`bin/agree2.py`; backup `bin/agree2.py.bak`).
Verified unaffected because they sit under the OLD cap and reproduce exactly: ResNet18
11,173,962 / ResNet10 4,903,242 / ResNet18_c100 11,220,132.

**The rule.** `infer_ntot`'s cap must exceed the largest arm's parameter count with margin.
Check it before adding any architecture above ~20M parameters — ResNet50 (25.6M) and
anything larger would be censored at the current 100M only above 100M, but the failure is
silent either way. Cross-check `infer_ntot`'s answer against `sum(block_sizes.json["n_b"])`
on every new weightwise arm; they must agree exactly.

This is the third defect in the coordinate-count layer (16: `n_b` wrong for nodewise; 17:
Lion sign-censoring of `drift/step`; 19: this). **Every one of them was silent and every one
of them moved a published number.**

## 20. Reducing an in-flight probe returns a moving number (cycle 29)

`agree2.py`'s STEADY window is "the last 50% of the records that exist", so a probe read at
89 records and again at 100 reports two different steady states. Measured on `p7-r34-lay-s1`:

| records | sys% | step% | excess |
|---|---|---|---|
| 89 | 51.4962 | 54.7917 | 0.9879 |
| 100 | 51.6727 | 55.2727 | 1.4690 |

A 49% change in the headline statistic, from nothing but reading it early. The `.out` file
shows 0 epochs while a job runs (stdout buffering), so an in-flight probe does not announce
itself the way an in-flight training run does.

**The rule.** Tabulate a probe only at its full record count — `PROBE=100` over 20 epochs
gives exactly **100 records, last step 9900**. Gate on `wc -l probe.jsonl` equal to the
expected count, exactly as the run tables gate on `epochs_done >= 100`. Cycle 29's 29.1
tabulates 24 of 32 `p7` dirs for this reason; the other 8 were at 49–96 records.

---

## 21. M1's `r` dial changes the meta-step-size as well as the pooling (cycle 33)

**What was wrong.** Two claims, both carried in `CONTINUE-HERE.md` and both built on reading
`additive` r=0 as a controlled full-pooling baseline:

1. "even full pooling helps (+1.39pp)" — CIFAR-10/ResNet18.
2. CORRECTIONS 13's framing that `r=0` is "the *maximally pooled* extreme", used as the
   endpoint against which the M1 curve is reported.

**What the code actually does** (`HF.py:265-293`, additive branch):

```
d    = beta - beta_prev          # realised Lion increment, |d_b| == ms EXACTLY
dm   = d.mean()                  # == ms*(2p-1),  p = fraction agreeing in sign
beta = beta_prev + dm + r*(d - dm)
```

CORRECTIONS 13 is right that r=0 gives every group the same increment. It is wrong that this
is a *controlled* baseline. Because Lion's increment has constant magnitude `ms`, averaging the
increments shrinks the shared step's advance to `ms·|2p−1|`. Moving r from 1 to 0 therefore
does two things at once: it pools the groups **and** it divides the meta-step-size by
`|2p−1|`. At layerwise `frac_neg` = 0.5484 → `|2p−1|` = 0.0968, a **10.3× reduction**.

**Structural verification** (measured, per Rule 4 — the r=0 endpoint that CORRECTIONS 13
inferred but never checked). A true full-pooling arm collapses every partition to one step
size, so its score cannot depend on the partition:

| granularity | m | `additive` r=0 | `zpool` r=0 |
|---|---|---|---|
| `resnet18_blocks` | 6 | 91.767 ±0.042 | — |
| `layerwise` | 62 | 92.587 ±0.674 | 87.740 ±0.138 |
| `nodewise` | 14,420 | 91.984 ±0.103 | — |
| `weightwise` | 11,173,962 | 45.005 ±2.603 | 87.763 ±0.036 |
| plain `scalar` reference | 1 | — | 87.772 ±0.139 |

`zpool` r=0 is granularity-invariant to **0.032pp** across 180,000× in m. `additive` r=0 spans
**47.582pp**. Probe evidence: `runs/zb/probe_zb-{l,w}-r0` show `z_mean` identical across all
reported tensors; `zb-l-r1` and `zb-plain` agree on `frac_neg` = 0.5483870967741935.

**Effect on the claims.**

| claim | status |
|---|---|
| "even full pooling helps (+1.39pp)" | **REFUTED.** True full pooling is −3.044pp vs plain layerwise. |
| M1 interior optimum, layerwise, +2.359pp vs r=1 (n=10) | **stands as an empirical curve**; its mechanism is not pooling |
| M1 interior optimum, nodewise, +1.140pp vs r=1 (n=3) | as above |
| 26.3's search for an agreement→gain mechanism | **explained as a confound.** The M1 gain depends on agreement because the effective meta-step-size is `ms·|2p−1|`. |
| CORRECTIONS 15's "cross-granularity pooling claims must use `additive` or `zmpool`" | **amended.** `additive`'s r is m-comparable as a formula, but its effect is dominated by the meta-LR rescaling, so it is not a pooling operator at all. |

**What decides it.** `ms-*` (52 jobs, cycle 33): a meta-step-size sweep on plain `scalar` and
plain `layerwise`. Pre-registered — if `scalar` at ms=1e-4 reaches 92.2–92.6, the whole M0/M1
family is meta-LR tuning and granularity contributes nothing to the win.

**Process note (Rule 4, third occurrence).** The first occurrence never checked the identity;
the second checked it with a statistic that could not fail; this one checked **one endpoint of
two** and inferred the other from algebra that was locally correct. The general lesson: verify
a dial at *both* extremes, and for an invariance claim, vary the thing the invariance is over —
here, the granularity.

---

## 22. The `weightwise` `additive` r=0 collapse is NOT explained by shared-term travel (cycle 34)

**The tempting sentence.** "At `weightwise`, `additive` r=0's shared step size advances at
`ms`·|2p−1| = 3.307e-7, so over 50,000 steps β travels 0.017 in log-space against the
ln(0.05/1e-6) = 10.82 it needs to escape a0=1e-6 — hence the 45.005 plateau."

**Why it is wrong.** The same arithmetic, run across the granularity ladder (FINDINGS 34.6,
startup window weighted in), predicts `nodewise` cannot escape either — β travel **1.31** vs
10.82 required — when `nodewise` plateaus at **91.984 ±0.103 (n=3)**. The model is refuted by
a case it gets backwards, not by a marginal one.

**What is actually going on.** CORRECTIONS 21 / FINDINGS 33.4 already established that
`additive` r=0 is **not** exact full pooling: it spans 47.582pp across granularities where true
`zpool` r=0 spans 0.032pp. Its pooled term is an **offset added to** each group's own update,
not a constraint replacing it. Every group's individual component still moves at ±`ms` per step
(travel 50 over a 100-epoch run) and can escape on its own. `weightwise` fails for a different
reason: at `step%` = 50.0165 against a 50.0119 null, each group's own meta-gradient is
statistically indistinguishable from noise, so β **random-walks** (RMS 1e-3·√5e4 = 0.22)
instead of drifting.

**Effect on the claims.**

| claim | status |
|---|---|
| `weightwise` `additive` r=0 = 45.005, "β cannot escape a0=1e-6" | **the number stands; the shared-term-travel explanation is REFUTED** |
| FINDINGS 33.4 "|2p−1| falls with m, so `additive` r=0 shrinks the meta-step further at finer partitions until β cannot escape" | **first clause verified (34.2), second clause REFUTED as the mechanism** |
| FINDINGS 34.3's `ms_eff` collapse curve | **stands** — it is a statement about where the five arms land, not about why weightwise dies |

**Process note (Rule 4 again).** The refuted model was checked at both *ends* of the ladder
(blk6 escapes ✓, weightwise does not ✓) and passed. It failed only at an **interior** rung.
Verifying a monotone mechanism at its two extremes is not verification — the interior is where
a wrong monotone story shows itself.
