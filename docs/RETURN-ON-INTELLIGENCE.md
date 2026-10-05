# Return on Intelligence (RoI)

> The measure of how much you actually *get* from AI — across every kind of
> usage, not just coding. The number an enterprise can point at and say
> "that's the one we run AI by."

This is the top-level standard. [THE-STANDARD.md](THE-STANDARD.md) (the
Realization funnel) is one *substrate* underneath it — the part that verifies a
coding outcome is real. RoI is the whole instrument.

---

## 1. Why this exists (and why nothing today is it)

Enterprises spend tokens across **everything** — coding, chat, research, drafting,
support, analysis, agent runs. They can see the bill. They cannot see the
**return**. Two camps have tried and missed:

- **Developer-productivity frameworks (DORA, SPACE)** suffer, in their own
  literature's words, *"attribution blindness — metadata-only tools cannot see
  which lines came from AI vs humans"*, and they are coding-only. Output-volume
  metrics are now openly discredited ("AI easily inflates the volume of code").
- **Top-down ROI frameworks (Gartner Return-on-Employee / Return-on-Future)** and
  **study-based uplift work (METR)** rely on surveys and hand-run RCTs. METR
  found AI made experienced devs **19% slower** while they *believed* they were
  faster (self-report off by ~40 points), and that **task-substitution** inflates
  apparent value (people do low-value "nice-to-haves" with AI).

The unmet need, stated plainly: a measure of realized AI value that is
**measured from the wire (not surveyed), spans all usage, includes the human
effort it cost, and can't be gamed on one axis.** That is RoI.

---

## 2. The unit and the denominator

**Unit of work** — a *unit of AI usage*: an interaction, task, or session, in
**any modality**. Every AI usage, coding or not, has the same shape:

```
intent (prompt) → output (response) → acceptance (kept vs redone) → outcome (used / realized / mattered)
```

This shape is what makes RoI universal. Coding adds rich verification (git:
committed → tested → shipped → survived → clean). Non-coding usage uses the same
spine with its own outcome signals (a draft published, a ticket resolved, an
answer not re-asked). The first two stages — **intent and acceptance — are
modality-agnostic and visible to an in-path proxy for *every* token spent.**

**Denominator (total cost to get the result):**

```
cost = token_cost (real 4-rate $)  +  effort_tax
effort_tax = Σ  rework_fraction × est_minutes × fully_loaded_labor_rate
```

The **effort tax** is the term token-counting misses and the literature demands
(human review priced at fully-loaded labor cost; AI often *raises* review time).
Rework is observed, not guessed — from acceptance/edit-distance and correction
loops in the proxy path. When labor rate is unset, effort_tax = 0 and the
denominator is labeled *token-only*; we never invent it.

---

## 3. The four value lenses (each named, each measured, each different)

We do **not** pick one definition of "value." Each lens answers a different real
question; we report all four, then compose them (§4). Each is normalized to
0..1 and may be `uninstrumented` (null) — never faked.

| Lens | The question it answers | How it's measured | When it's the one you want |
|------|------------------------|-------------------|----------------------------|
| **Realization** | *Did the spend become something real and kept?* | Verified-outcome conversion (the funnel: shipped/survived/clean for code; used/not-redone for the rest) | The floor. Always on. Kills spend that produced nothing durable. |
| **Acceptance** *(Take Rate)* | *Did you keep what it gave you, first try?* | Edit-distance between what the AI proposed and what you kept; regeneration / re-ask rate. Modality-agnostic, **available in-session.** | Real-time coaching; raw output quality; any usage type. |
| **Lift** *(counterfactual)* | *Did it actually make you faster/able vs not using it — or vs a cheaper model?* | **Behavioral, never self-report** (`src/value/lift.ts`). METR's method: time-with-AI from 10-min concurrency windowing of session timestamps; a transcript/A-B TSF as a **soft upper bound**, then discounted for selection/substitution/concurrency to a **bounded range** via the ordering inequality `Lift_old ≤ Lift_value ≤ Lift_new ≈ TSF`. | Deciding what's worth it; model/approach choice. (Hardest; reported as a range, never a point.) |
| **Impact** | *Of what was realized, how much actually mattered?* | Objective weight: reached production, blast radius (files/callers touched), criticality, incident-freedom. | Portfolio / exec view. Counters the "nice-to-have" substitution bias. |

Why four and not one: a single numerator always hides a failure mode.
High Acceptance with zero Impact = you happily shipped things nobody needed.
High Realization with negative Lift = you kept code that AI made you *slower* to
produce. Only seeing them together tells the truth.

---

## 4. The composite — derived, not chosen

The four lenses are not four metrics we liked. They are the **four independent
ways raw output overstates value** — a spanning set of its failure modes. Each
lens, normalized to [0,1], is a *conditional survival rate* along the chain
**tokens → kept → caused → mattered**:

| Leak (how output lies about value) | Condition that closes it | Symbol |
|---|---|---|
| It didn't last | Realization | ρ |
| You had to rewrite it | Acceptance | α |
| You'd have done it anyway | Lift (counterfactual) | λ |
| It didn't matter | Impact | ι |

### 4.1 Why they MULTIPLY (and what that does and does not resist)

These are *necessary conditions in series*. The probability a unit of spend
becomes real intelligence-value is the joint probability of clearing all of them,
and by the **chain rule of probability over a funnel of necessary conditions**,
the joint of a chain is the product:

```
π = ρ · α · λ · ι
```

Same mathematics as manufacturing yield through sequential quality gates, or the
reliability of a series system (R = ∏ Rᵢ). What follows is a specific, bounded
resistance — **resistance to SINGLE-AXIS gaming** — and it is derived rather than
asserted: pumping one axis to 1.0 while another sits at 0.05 leaves π ≤ 0.05, so
**the score is hostage to its weakest link.** That is not immunity to Goodhart's
law. An optimizer who can move every lens, or who can move the MEASUREMENT of a
lens rather than the thing it stands for, is not constrained by this structure at
all; multiplicativity raises the cost of gaming, it does not close the door. The
funnel chain-rule reading is itself a model of how value converts, not something
this repository has measured. The arithmetic
mean every dashboard uses, (ρ+α+λ+ι)/4, has no such floor — a single pumped axis
lifts it regardless of a zero elsewhere. The product structure is *forced* by the
requirement "no single axis can be gamed."

### 4.2 Why the GEOMETRIC mean specifically (what is forced, and what is disclosed)

For a comparable 0–100 **Index** we need a mean M(ρ,α,λ,ι) on the same scale.
There are infinitely many means; the **form** is pinned down by one requirement
that value-composition demands — **multiplicative consistency**: the index of a
two-stage process equals the product of the stage indices, `M(x·y) = M(x)·M(y)`.

> **Kolmogorov–Nagumo–de Finetti (specialized).** Every quasi-arithmetic mean is
> `M_φ(x) = φ⁻¹(Σ wₖ φ(xₖ))` for a continuous strictly-monotone generator φ.
> The generator that makes the mean multiplicative — `M(x·y) = M(x)·M(y)` for all
> x,y — is **φ = log**, i.e. the (weighted) **geometric** form. Among *symmetric*
> means it is the unique multiplicative one.

So the functional form **follows from those two axioms** — assume the aggregator
is quasi-arithmetic and multiplicative, and it must be a weighted geometric mean.
Both axioms are modelling choices. "Quality composes the way value composes along
the funnel" is a stance this project adopts because a funnel multiplies through;
it is not an economic result, and nothing here has tested it against outcomes.
Algebraically the expression coincides with a constant-returns-to-scale
**Cobb–Douglas form** — an analogy for the shape only. No production function has
been estimated on this ledger, so wₖ are not measured output elasticities of any
real output:

```
RoI Index = 100 · ρ^wρ · α^wα · λ^wλ · ι^wι ,   Σ wₖ = 1   (Cobb–Douglas, CRS)
```

Two things are **disclosed, not forced**, and we say so plainly:

1. **The weights.** wₖ is the elasticity of **the Index** w.r.t. lens k —
   `∂ln(Index)/∂ln(xₖ) = wₖ` — "a 1 % gain in lens k lifts the Index wₖ %."
   That is an algebraic identity of this formula, and says nothing about output,
   productivity or value: it describes how our own score responds, not how the
   world does. The values are **disclosed preferences** informed by the
   literature (§7), normalized to sum to 1. The
   implementation divides by Σw internally, so the raw defaults
   `{1.0, 0.7, 1.2, 1.0}` realize elasticities `{0.26, 0.18, 0.31, 0.26}`. Set
   them **equal** (0.25 each) and you recover the **symmetric axiomatic index** —
   the unique symmetric multiplicative mean — for a buyer who wants no editorial
   weighting at all (`weights: {1,1,1,1}`).
2. **The substitution θ** (§4.3): θ = 0 (geometric) is the distinguished neutral
   point, but the whole CES family is exposed.

Given multiplicativity, one consequence is not a further taste choice: any zero
lens collapses the Index, no matter the weights. (Multiplicativity itself remains
an assumption — see above.) Proof: GM(x·y) = ∏(xₖyₖ)^wₖ =
∏xₖ^wₖ · ∏yₖ^wₖ = GM(x)·GM(y); the arithmetic mean fails it,
Σwₖxₖyₖ ≠ (Σwₖxₖ)(Σwₖyₖ). (Tested in `test/equation.test.ts`.)

One property of that collapse deserves naming: it is a **policy veto embedded
in the aggregation**, and it is *discontinuous* — a lens crossing from 0.01 to
exactly 0 moves the Index from small to zero in one step, so noisy
classification near zero can flip a ranking. The composite-indicator
literature's alternative is a hurdle decomposition — `Index = H · G₊`, a hard
eligibility indicator times a smooth strictly-positive score (or a penalized
geometric mean) — which keeps low compensability without the cliff. We keep
the single-product form deliberately: the veto **is** the message (a collapsed
lens cannot be scored away), and separating it would blunt exactly the property that
makes the Index resistant to single-axis gaming. But the choice is a design
stance, not a mathematical necessity, and an integrator who needs ranking
stability near zero should use the hurdle form on top of the same lenses.

### 4.3 The substitution knob (a principled family, one distinguished default)

The geometric mean is the θ→0 case of the **CES / power mean**
`M_θ(x) = (Σ wₖ xₖ^θ)^{1/θ}` (`weightedPowerMean` in `lenses.ts`):

| θ | mean | meaning |
|---|---|---|
| 1 | arithmetic | perfect substitutes — gameable; never the default |
| **→ 0** | **geometric** | unit elasticity of substitution; scale-free; multiplicative |
| → −∞ | minimum | Leontief, pure weakest-link |

θ is the CES **substitution parameter**, not the elasticity of substitution
itself: the elasticity is `σ = 1/(1−θ)`, so θ=0 gives σ=1 (the unit-elasticity
geometric case in the table above), θ=1 gives σ=∞, and θ→−∞ gives σ→0. σ is
what governs how much surplus on one axis may compensate a deficit on another.
Geometric (θ=0) is the distinguished neutral point; a buyer who wants it even
harder to game slides θ<0 toward the min.

### 4.4 RoI is an INTERVAL, not a number (the honest core)

Lift λ is a behavioral, partially identified lens: it asks how the observed
workflow compares with a disclosed baseline, not whether AI caused the outcome.
The fundamental problem of causal inference says you cannot observe both the
with-AI and without-AI worlds for the same task, so **λ is not point-identified.**
Selection, substitution, and concurrency can move the estimate in different
directions. We therefore report a disclosed interval and sensitivity range, not a
causal money credit. A separate registered randomized study is required before
Segreant can state a scoped causal effect or net benefit.

```
RoI ∈ [RoI_low, RoI_high]      (point = interior estimate)
```

The interval's width is set by (a) baseline/counterfactual uncertainty and (b)
instrumentation coverage. Additional valid evidence can narrow those assumptions,
but the observed-only score may move up or down when a missing lens is measured.
This turns the metric into a roadmap: *here is the observed result, its disclosed
coverage, and exactly which evidence would reduce the remaining assumptions.*
Unknown lenses are excluded from the observed-only score and are also represented
in the full sensitivity interval; `indexIsUpperBound` is retained only as a false
compatibility value so older consumers cannot mistake the observed score for a
ceiling.

The identification interval above is not the only width the Index carries. The
lenses are also *estimated from finite data*, so a second, **statistical** width
exists — and the two are folded together in the `compositeInterval`: each lens's
own bounds (today: the realization rate's anytime-valid confidence sequence, §10)
are substituted into the aggregator at their joint endpoints. Because the
aggregator is **monotone in every lens**, endpoint substitution brackets the
truth **without any lens-independence assumption** — correlated lenses cannot
break it, only make it conservative. The interval names its `sources`: a lens
with no interval of its own enters as a point and is *not* claimed as covered.
One statistical sequence enters today, so its level is the joint level; as more
lens sequences are wired, the α is split across them before folding. A related
disclosure travels with the frontier: **lens redundancy** `d_eff = m²/Σr²ᵢⱼ`,
the effective number of independent dimensions the lens system measures across
contexts — `d_eff ≪ m` means the lenses co-move and the composite is silently
overweighting one latent factor. It is a disclosure, never an automatic
reweighting: correlation alone doesn't prove redundancy.

### 4.5 The two faces (kept distinct on purpose)

The same evidence projects into two honest objects. The first is unitless and
comparable; the second is dollars and decides whether to keep paying.

**Face 1 — RoI Index (0–100 + coverage):** the weighted geometric mean above
(§4.2). Unitless and scope-limited to the connected lenses and evidence window;
it is the dashboard hero, not a universal productivity or causal measure.
(`roiIndex` in `lenses.ts`.)

**Face 2 — observed value scenario (the money view).** A descriptive,
dimensionless ratio computed *directly* as manual-equivalent value ÷ honest cost
under the disclosed assumptions (`returnRatio` in `lenses.ts`):

```
                Σ_realized  baselineMin(u) · (wage/60) · acceptance(u)
ObservedScenario = ─────────────────────────────────────────────────────────
                  tokenCost   +   supervisionMin · (wage/60)
```

`returnRatio.causalRatio`, `causalRange`, and `paysForItself` remain null on
this ordinary value spine. A qualified causal-study result is a separate object
with its own protocol identifier, cost source, outcome, quality guardrail, and
conservative bound; it is never derived by multiplying this scenario by Lift.

Every term is defended:

- **Numerator — realized, manual-equivalent value, net of rework.** Only work
  that *realized* (ρ) is counted, each priced at its **manual baseline** — what
  the kept output would have cost a human (`baselineMin × wage`, an auditable org
  input, never a self-reported speedup) — and discounted by first-pass
  **acceptance** α (reworked output is worth less). This is value measured in the
  worth of the work, not in the tokens it took (which would be circular).
- **Denominator — the *honest* cost of the intelligence.** Tokens **plus your
  measured time supervising the AI** (`supervisionMin`, METR 10-minute windowing
  over real request timestamps, §3), priced at the wage. Pricing your own time is
  what keeps the ratio real: token cost alone makes a \$4 feature look like a 100×
  return; adding the hour you actually spent driving it lands the number where the
  evidence does (METR's ~1.4–2× value, not the ~3× raw speed). The metric
  **refuses to print a dollar return** until supervision time is measured — it
  will not invent the denominator (`basis: 'none'`).
- **Behavioural Lift is an observational lens, not a causal money credit.**
  The historical `RoI_gross` / `RoI_causal` terminology describes a formula
  from before Segreant had a dedicated causal-evidence lane. Behavioural Lift, a
  time-speed estimate, and a manual-equivalent valuation do not establish the
  outcome that would have occurred without AI. The current product therefore
  renders this money value only as an **observed/manual-equivalent value
  scenario** and keeps the legacy causal fields null.

  A future Segreant causal net-benefit result is deliberately a separate object.
  It requires the registered randomized-study conditions in
  [CAUSAL-EVIDENCE-PROTOCOL.md](CAUSAL-EVIDENCE-PROTOCOL.md): frozen
  intervention/control definitions, pre-exposure random assignment, completed
  execution and outcome lineage, explicit cost-source classification, a
  predeclared value or quality guardrail, and a conservative lower confidence
  bound. A model-versus-model experiment can support a scoped comparative
  claim; an AI-paid-for-itself claim additionally needs a no-AI or incumbent
  control, full-cost accounting for both arms, a currency/measured-labour
  outcome basis, and a positive lower bound on causal net benefit.

The two faces differ by Jensen's inequality (value sums dollars per-unit; the
Index composes lenses) — correct, because one is a sum of dollars and the other a
capability scorecard.

Alongside, **the frontier ("what's best for you")** breaks RoI Index and cost
down by model × task-type, so *"is Opus worth 5× Haiku for my refactors?"* is a
number, not a guess.

The cost column in that breakdown is the **attribution window's total spend** —
what the work cost — booked to the model that spent the most in the window. That
is the right basis for "what did this context cost" and the wrong one for "what
does this model cost", because a window containing two models charges both to
the top spender. The cheaper-model trial therefore does **not** use it: it prices
each model from that model's own attributed spend and refuses any unit whose
window is too mixed to attribute (see `src/value/frontier.ts`). Read the
model × task-type table as a cost-of-context view, not as a model price list.

### 4.6 Risk — two named treatments (a return needs more than a mean)

A point estimate is not a decision. RoI prices risk twice, on purpose:

1. **Balance risk (cross-sectional).** The geometric mean is *already*
   risk-averse across lenses: by AM–GM, an imbalanced profile (0.9, 0.1) scores
   far below its arithmetic average, so the Index punishes fragility — a tool
   that's brilliant on one axis and broken on another cannot hide.
2. **Estimation risk (longitudinal).** How sure are we? The Index is partially
   identified (§4.4), so we expose a **certainty-equivalent** at a buyer's
   risk-aversion γ ∈ [0,1] (`certaintyEquivalent` in `lenses.ts`):

   ```
   CE(γ) = point − γ · (point − low)
   ```

   γ = 0 returns the interior point; γ = 1 returns the conservative lower bound
   (every un-instrumented necessary condition assumed adverse). It is coherent —
   monotone in γ, never exceeds the point, degenerates to the point when the
   interval is a point. "Even under conservative assumptions, RoI ≥ CE(γ)."

   One classification matters for anyone auditing this: **CE(γ) is a decision
   policy over an identified interval, not statistical evidence.** It is not a
   confidence bound, not a posterior mean, and it carries no coverage guarantee
   of its own — γ encodes the *reader's* risk attitude, chosen by the user, and
   the honest statistical objects remain the interval itself (§4.4) and the
   anytime-valid sequences (§10). Reporting CE(γ) without saying which γ was
   chosen would be laundering a preference as a measurement; the CLI always
   prints γ next to the number.

---

## 5. What is genuinely new here (honest)

The *components* are established mathematics — geometric mean, CES, Manski
partial-identification bounds, funnel chain-rule, proper-scoring honesty. **The
invention is the synthesis**, which has not been built:

1. **The four lenses as a spanning set.** Realization/Acceptance/Lift/Impact are
   *derived* as the four independent ways raw output overstates value (§4), not a
   convenient list — and Lift is what makes it return on *intelligence*, not on
   spend.
2. **Value-conversion modelled as a necessary-condition chain ⟹ the aggregator
   follows.** Modelling conversion as a chain of necessary conditions makes
   value multiplicative; multiplicative consistency then gives the geometric
   mean via the Kolmogorov–Nagumo characterization (§4.2). What is a theorem is
   the resistance to SINGLE-AXIS gaming, conditional on that model. Immunity to
   Goodhart's law is not claimed, and the model is a declared assumption.
3. **Interval-valued, honest-by-construction.** RoI exposes a point together with
   its stated baseline, coverage, and sensitivity range rather than a false
   universal guarantee. Valid evidence may narrow uncertainty, while measuring a
   missing lens can move the observed score in either direction (§4.4).
4. **Cross-modality, measured from the wire.** The universal
   intent→acceptance→outcome spine measures value from *any* token spend (not just
   commits), from the proxy path — solving the "attribution blindness" DORA/SPACE
   name as their blocker and avoiding the self-report bias METR documents.
5. **A decision, not just a score.** The per-context frontier turns the metric
   into "what's best for *you*."
6. **A money number that can't be gamed by ignoring your time.** The RoI return
   prices the denominator as tokens **+ measured supervision time**, values the
   numerator at the work's manual-equivalent worth (not the tokens it cost), and
   credits the counterfactual exactly once — so it lands at the literature's
   ~1–2×, not a fantasy multiple, and refuses to print a dollar figure until your
   time is measured (§4.5). Paired with two explicit risk treatments — balance
   (the geometric mean) and estimation (the γ certainty-equivalent, §4.6).

What we are **not** claiming: that we invented the geometric mean, CES, or
partial identification (we did not — §4 cites them); that any single lens is novel
in isolation; that Lift is easy (it's the hardest, modeled, clearly labeled as an
interval); or that non-coding outcome capture is finished (the spine is universal;
the per-modality outcome hooks beyond code are the active build — see §6). Stating
exactly which bricks are standard is what makes the structure credible rather than
hand-wavy.

---

## 6. Honest scope / build order

- **Now**: lens math + the geometric-mean composite (RoI Index) + the money
  number (RoI return: realized manual-equivalent value over tokens + measured
  supervision time, counterfactually credited once) + the risk-adjusted
  certainty-equivalent, over the coding substrate (Realization funnel).
  (`src/value/lenses.ts`, `segreant roi [--labor-rate <w>] [--risk <γ>]`.)
- **Next**: the per-context frontier (model × task-type) from proposal→outcome
  linkage; behavioral Lift via model A/B on like tasks.
- **Then**: non-coding modality capture (chat/research/writing/agent outcome
  signals) through the same proxy + `report` spine, so RoI covers all token use.

Until a signal is wired, its lens reads `uninstrumented` and the index is honest
about coverage. The path to a more trusted number is to instrument the next
evidence source, inspect the sensitivity result, and preserve the possibility that
the measured value moves either way — never to game one lens.

---

## 7. Grounding & provenance (why the defaults are what they are)

The design is calibrated to the empirical record, not invented:

- **Self-report is rejected.** METR's RCT (16 experienced devs, 246 real tasks on
  mature repos) found AI made them **19% slower** while they *believed* they were
  **24% faster** — a 43-point perception gap. So Lift is behavioral only.
- **TSF is an upper bound, hence the range.** METR's transcript analysis (5,305
  Claude Code transcripts) yields TSF ~1.5–13× but explicitly bounds *value*
  uplift below it via task-selection / substitution / concurrency biases. Their
  2026 survey shows a persistent ~3× *speed* vs ~1.4–2× *value* gap. We encode
  this as the ordering inequality + discount factors.
- **Throughput is discredited; quality/effort dominate.** "The Fast and Spurious"
  (arXiv 2510.24265) shows GenAI redistributes effort downstream (review burden,
  cognitive load) rather than eliminating it — frequent users report *higher*
  exhaustion. "Beyond the Commit" (arXiv 2602.03593) shows 86% satisfaction with
  <1 hr/week saved for most, and that commits are the wrong unit. This is why the
  lens weights favor Realization/Impact/Lift over raw Acceptance, and why the
  denominator includes the effort tax.
- **Tokens are mostly overhead.** Field data shows 85–95% of agentic tokens go to
  orientation / context re-send / retries — so token *volume* is a cost signal,
  never a value signal. RoI treats it accordingly.
- **The cautionary precedent.** In 2026 employees at Meta ("Claudeonomics") and
  Amazon ("KiroRank") built internal leaderboards ranking colleagues by tokens
  used. Amazon took KiroRank down after staff ran agents on low-value tasks to
  climb it and compute costs rose (CIO, 2026:
  https://www.cio.com/article/4178825/amazon-deletes-devs-tokenmaxxing-leaderboard-to-minimize-costs-2.html);
  Meta's dashboard was taken down in April 2026 (Fortune, 9 Apr 2026:
  https://fortune.com/2026/04/09/meta-killed-employee-ai-token-dashboard/). RoI
  is an outcome-based answer to that failure, and its geometric-mean composite
  makes single-axis gaming harder: inflating one lens cannot offset a weak one.
  It does not make gaming impossible; the drift alarm (§11) exists for the rest.

**Sources:** METR RCT (arXiv:2507.09089); METR transcript analysis (metr.org,
Feb 2026); METR 2026 technical-worker survey; *The Fast and Spurious* (arXiv
2510.24265, HumanAISE@FSE'26); *Beyond the Commit* (arXiv 2602.03593,
ICSE-SEIP'26); SPACE (Forsgren et al. 2021); DORA AI insights. Full synthesis in
the project's research notes.

### 7.1 Baseline minutes: cited, refreshable, personally calibrated

`liftFromData`'s numerator needs one more input per realized unit: how many
manual minutes that task-type would have taken. Before this was a flat,
hand-picked, unsourced table. It now resolves per task-type from three sources,
in priority order (`src/value/liftBaseline.ts`), and every number is labeled with
which source produced it:

1. **An explicit override in `config.lift.baselineMinutes`** — always wins. This
   is unchanged: an auditable org input, exactly like the labor rate, never
   silently replaced.
2. **This machine's own pre-tracking git history**, when there's any. Commits
   from before Segreant recorded its first tracked request ANYWHERE (a global
   cutoff, not per-project) are treated as pre-tracking evidence. Consecutive
   commits whose gap looks like real, continuous working time (bounded 2–90
   minutes by default — short enough to exclude fixup/squash noise, long enough
   to exclude breaks) are classified by the same task-type classifier the
   realization engine already uses (`classifyTaskType`), and the gap becomes a
   real, behavioral personal-minutes sample. Two honest limits on the cutoff,
   disclosed rather than hidden: it can only reflect AI use Segreant has itself
   tracked, so AI-assisted work from *before* Segreant was installed reads as
   "manual"; and it's the minimum timestamp in the (retention-prunable) request
   ledger, so on a long-lived install it can drift forward as old requests age
   out, rather than staying pinned to the true first-ever request. Neither is
   fixed by more engineering here — they're exactly why this prior is always
   shrunk toward the population prior below, never trusted outright.
3. **A cited population prior** (`baselines/lift-baselines.json`), anchored to
   METR's published, human-timed task-completion research (Time Horizon 1.1,
   2026-05-08: metr.org/time-horizons, arXiv:2503.14499) — METR times skilled
   professional engineers completing real tasks and reports the task LENGTH, in
   that human-timed unit, at which frontier models succeed 50%/80% of the time.
   METR does not publish a breakdown matching this project's task-type taxonomy,
   so the per-task-type minutes are this project's own calibration against that
   published scale, not a METR output — disclosed as such in the manifest file
   itself. These values are unchanged from Segreant's earlier illustrative
   defaults; the METR anchor is an order-of-magnitude sanity check against a
   real, cited human-timed scale, not a re-derivation of the numbers from METR
   data. Refreshable via `segreant baseline --refresh --url <manifest>` (a
   user-writable cache under `~/.segreant/baselines/` overrides the bundled
   floor; `segreant baseline` alone shows source/age/staleness) — but honestly,
   unlike `segreant pricing`, there is no established machine-readable feed for
   this, so `--url` is required every time: there is no saved or invented
   default to silently reuse.

Sources 2 and 3 are combined, not just chosen between, via a continuous-data
analogue of §8's Beta-Binomial shrinkage:

```
minutes = (personalSum + κ·populationMean) / (personalN + κ)
```

the same "evidence plus κ pseudo-observations at the prior mean" shape, but for
a continuous positive mean instead of a 0..1 rate. `κ` here (20 pseudo-commits)
is a **fixed, disclosed constant, not empirically estimated** — §8's Beta-
Binomial prior can estimate its own shrinkage strength from the dispersion
across every model×task cell in the whole ledger, but a personal git baseline
typically has only a handful of task-type buckets, too few to separate real
spread from noise the same way. A fixed, conservative constant is the honest
choice over pretending to fit one from too little data. None of this touches
`liftFromData`, `boundedLift`, or the Manski interval mechanics above — it only
sharpens one of their inputs.

**Time Reclaimed** (`src/value/timeReclaimed.ts`, `segreant saved`) is this same
baseline math read as a calendar unit instead of a ratio: manual minutes of
REALIZED work at these resolved task-type baselines, minus measured
time-with-AI, in work-weeks — with the baseline band above as the interval,
never a false point. It inherits every caveat here unchanged: baseline-
estimated, not a controlled A/B; a unit that died before realizing (or whose
task type has no baseline) earns zero credit while its AI time still counts
against the total, so a workflow that mostly produces unrealized churn can't
show a headline number it didn't earn.

### 7.2 AI-side efficiency: the Acceptance-driven Lift discount

§7.1 sharpened the manual-baseline side of the TSF ratio. It never touched the
other side: measured time-with-AI treats a focused three-turn session and a
forty-turn session that flailed to the same result identically, because both
produce the same wall-clock duration. `src/value/liftEfficiency.ts` adds a
behavioral signal for that — content-free, computed entirely from data already
in the pipeline.

Each realized, baseline-covered work unit already carries an Acceptance rate
(`WorkUnit.acceptance` — edit-distance between proposed and kept output,
structural, never semantic; the same figure that already drives the Acceptance
lens of the RoI Index). `liftFromData` pools the Acceptance rates of the units
feeding one Lift calculation and shrinks that pool toward this ledger's OWN
overall first-pass acceptance rate (`RealizationReport.firstPassAcceptance`)
via `reliability.ts`'s `shrinkRate` — the exact empirical-Bayes machinery §8
describes, reused rather than reimplemented, with a fixed κ=20 for the same
reason as §7.1's baseline blend: a single Lift calculation typically covers too
few units to separate real spread from noise the way §8's cross-cell dispersion
estimate can. The shrunk rate maps to a small, disclosed multiplier bounded to
`[0.85, 1.15]`:

```
efficiency = clamp(1 + (shrunk − ledgerAcceptance), 0.85, 1.15)
```

**Why shrink toward the ledger's own rate, not a population figure.** Unlike
§7.1's baseline-minutes prior, there is no cited external source for "typical
AI first-pass acceptance rate" the way METR publishes one for task-completion
time — inventing one would violate the same discipline this project holds
everywhere else. The only honest prior available is the user's own broader
history.

**Why a fourth point-multiplier, not a separate interval-narrowing mechanic.**
The shipped implementation feeds the structural efficiency signal into
`boundedLift` as a fourth discount alongside `selection`/`substitution`/
`concurrency` — all four multiply into the same `point` estimate, and because
`low = point × 0.7` when no A/B floor is supplied, a high-efficiency session's
`point` and `low` rise together while `high` (the TSF ceiling) is untouched,
narrowing the interval's *width* as a side effect of one well-understood
mechanic rather than a new one. This is the simpler, more consistent choice: it
reuses `boundedLift` exactly as built, never redefines "the interval
mechanics" — the same discipline §7.1 states explicitly ("None of this touches
`liftFromData`, `boundedLift`, or the Manski interval mechanics above — it only
sharpens one of their inputs") applied to this input too.

Absent Acceptance data (no proposal captured for any covered unit) or an
uninstrumented ledger (`firstPassAcceptance` still null), the signal returns
multiplier `1` — the prior, unmodified numeric result — with a note explaining
why. Wired through `liftOptionsFromStore` (`src/value/realization.ts`); unit
math lives in `test/lift-efficiency.test.ts`, end-to-end wiring in
`test/lift-source.test.ts`.

---

## 8. Reliability — trust in proportion to evidence (empirical Bayes)

A raw rate lies with confidence on thin data: **2 of 2 realized (100%)** out-ranks
**140 of 200 (70%)**, and the noisy small cell then captures budget and "best
model" recommendations. This is the batting-average fallacy, and unaddressed it is
the fastest way a skeptic discredits the whole tool.

The response is **empirical-Bayes shrinkage**: pull each cell's rate toward the
population mean in proportion to how little data backs it. The intuition is the
one James–Stein made famous, but the theorem itself does **not** apply here.
James–Stein dominance is a result about p ≥ 3 Gaussian means with *known*
variance under total squared-error loss; this estimator is Beta–Binomial with a
hyperprior *estimated from the same cells*, so no dominance guarantee carries
over. Shrinkage here is a modelling choice that usually reduces error on thin
cells — not a proof that it beats the raw rate. It also assumes the cells are
**exchangeable**; where they are not, the pooled mean is the wrong target. We
model realized/total as **Beta–Binomial** — each context's
`k` of `n` outcomes has its own success probability drawn from a shared
`Beta(α, β)` prior — and report each context's **reliable rate** as the posterior
mean:

```
ρ̂ = (k + κ·μ) / (n + κ) ,   μ = α/(α+β) (population rate),  κ = α+β (prior strength)
```

A thin cell is pulled to μ; a data-rich cell barely moves. Crucially **κ is
estimated from the data, not chosen** (the *empirical* in empirical Bayes): by
method of moments on the beta-binomial's extra-binomial variation (Williams 1982),

```
ρ_icc = ( Σ(kᵢ − nᵢμ)² / [μ(1−μ)] − N ) / Σ nᵢ(nᵢ−1) ,   κ = 1/ρ_icc − 1.
```

Tightly-clustered cell rates ⟹ their spread is noise ⟹ large κ ⟹ heavy shrinkage;
genuinely spread rates ⟹ real differences ⟹ small κ ⟹ light shrinkage. Alongside
each shrunken figure we can show the **evidence weight** `n/(n+κ) ∈ [0,1]` — a
plain-language confidence. (`src/value/reliability.ts`, `test/reliability.test.ts`.)
This supports offline research only. Segreant does not currently expose a
shadow-price or generic same-budget allocation decision: model×task and project
cells can still be unlike work, so shrinkage alone cannot make a cross-context
optimization causal or comparable. The retained raw allocator is explicitly
`exploratory_raw`, not reliability-adjusted decision support.

---

## 9. The Shadow Price of Intelligence — the marginal dollar

Every FinOps tool reports where the money **went**; none says where the next dollar
should **go**, or whether it is worth spending at all. That is a constrained
optimization whose solution carries one decision-grade number.

Model each context's realized value as concave in the spend routed to it —
diminishing returns, the honest default (easy wins land first; contexts saturate):

```
Vᵢ(s) = aᵢ · s^β ,   0 < β < 1   (β disclosed; default 0.5),   aᵢ = Vᵢ / sᵢ^β  (fit)
```

Maximizing total realized value `Σ Vᵢ(sᵢ)` subject to a fixed budget `Σ sᵢ = B` is
a **water-filling** problem. Its Lagrangian `ℒ = Σ aᵢsᵢ^β − μ(Σsᵢ − B)` gives the
first-order condition `Vᵢ′(sᵢ) = μ` for every funded context — **at the optimum
every dollar earns the same marginal return μ**, the Lagrange multiplier. Because
the objective is homogeneous of degree β, Euler's theorem closes it in one line:

```
optimal split   sᵢ* = B · wᵢ / Σⱼ wⱼ ,   wᵢ = aᵢ^{1/(1−β)}
shadow price    μ  = β · V*(B) / B          (V* = total realized value at the optimum)
```

**μ is the headline.** `μ ≥ 1` ⟺ the next AI dollar returns more than a dollar of
realized value (under-invested — room to grow); `μ < 1` ⟺ the next dollar returns
less (past positive margin — cut, don't grow). This is the answer to *"what is one
more dollar of AI budget worth to me, right now?"* — a question the market cannot
otherwise answer. And because the split follows `aᵢ^{1/(1−β)}` rather than `aᵢ`,
**concavity forbids winner-take-all**: the best context gets more budget, never all
of it — the honest antidote to "pour everything into the top-scoring model." β is
disclosed like the Index's weights and θ; the concave shape is a planning
assumption that travels with the output. (`src/value/marginal.ts`,
`test/marginal.test.ts`; currently withheld from `segreant budget --recommend`
until a within-task, controlled allocation contract exists.)

### 9.1 β estimated from your own curvature (never silently assumed)

When history supports it, β is **estimated from the org's own data** rather than
assumed. The estimator is chosen for one property: it cannot be biased by context
quality. Comparing *different* contexts confounds β with quality (teams route more
spend where value is higher, so a pooled log-log regression inflates β). So we
never compare across contexts. Within one context observed in the window's two
halves, its quality `aᵢ` cancels exactly:

```
V₂/V₁ = aᵢs₂^β / aᵢs₁^β   ⟹   β = log(V₂/V₁) / log(s₂/s₁)
```

One slope per context; the estimate is the **median** across contexts, so a
minority whose quality genuinely shifted between halves can't drag it. Gates, all
disclosed in the output: positive spend and value in both halves; spend moved
≥10% (otherwise the slope is unidentified); ≥3 usable pairs; and the median must
land inside (0.05, 0.95) — a median at or above 1 means *no diminishing returns
were detected*, and the honest response is to keep the disclosed default and say
why, not to clamp an estimate the data rejects. β's provenance (estimated vs.
default, and from how many contexts) belongs with any future, controlled
within-task allocation experiment; it is not currently presented as a product
allocation recommendation.
(`estimateBetaFromPairs` in `src/value/marginal.ts`.)

## 10. Anytime-valid — the number you are allowed to watch

Every monitoring product ships intervals with a flaw its users never see: a
classical 95% interval is only valid if you look **once**, at a pre-registered
sample size. A dashboard invites the opposite — glance at every refresh, act the
moment the number looks good. Under that use the real error rate of a fixed-n
interval grows without bound (the *optional stopping* / "peeking" problem that
forces clinical trials into sequential designs). In our simulation, watching a
stream at every step, a classical 90% interval was wrong at some point in **~64%
of runs**. A product whose brand is "never a dishonest number" cannot show that.

The fix is a **confidence sequence**, built from an e-process. For a realization
stream `x₁..xₙ` and a candidate rate `p`, the mixture likelihood ratio

```
Mₙ(p) = ∫ q^k (1−q)^{n−k} dBeta(a,a)(q)  /  p^k (1−p)^{n−k}
```

is a nonnegative martingale with `E[M₀] = 1` when `p` is the true rate, so
**Ville's inequality** bounds it over *all* time at once: `P(∃n: Mₙ(p) ≥ 1/α) ≤ α`.
The interval at any moment is simply every rate not yet rejected:

```
CSₙ = { p : Mₙ(p) < 1/α }      — valid SIMULTANEOUSLY at every n
```

Peek whenever, stop whenever, act whenever: the guarantee holds. In the same
simulation the confidence sequence violated its 10% budget in **6.0%** of runs —
inside budget — while the classical interval failed in 63.8%.

Three honest notes. (1) The price is width: an anytime-valid interval is ~1.5–2×
wider than a fixed-n one. We show that cost instead of hiding it — a narrower
number would be a lie about how dashboards are used. (2) It is **display-only**:
it never feeds the Index or its partial-ID interval, so nothing about §4–§5
changes meaning. (3) The implementation needs no gamma function and no
dependency — the Beta ratio is built by the exact recurrence
`B(x+1,y) = B(x,y)·x/(x+y)`, and `log Mₙ(p)` is quasi-convex with its minimum at
`k/n`, so the interval falls out of bisection. (`src/value/anytime.ts`,
`test/anytime.test.ts` — including the simulated-peeking coverage test.)

## 11. The rate-drift alarm — detecting that a rate is not constant

> **Named for what it observes.** This test rejects "one constant Bernoulli rate
> generated this stream". Drift is a *necessary* signature of a metric being bent
> under incentive pressure, which is why the alarm is worth having — it is not a
> *sufficient* one. Calling a firing "Goodhart" would assert an incentive
> mechanism the 0/1 stream carries no evidence about. Below, Goodhart is the
> motivating hypothesis the alarm sends you to investigate, never its finding.

Goodhart's law is the fate of every metric: once a number is a target, people
optimize the number instead of the value it stood for. A gamed metric doesn't
announce itself — it shows up as the rate **drifting** (acceptance creeping up
while nothing else improves; realization sagging as easy wins get cherry-picked).
The alarm detects exactly that, with the same anytime-valid guarantee as §10,
reading **no content** — drift is visible in the 0/1 outcome stream alone.

The construction is **universal inference** (a running-MLE e-process). Race two
forecasters over the stream: a *predictive* alternative — a Krichevsky–Trofimov
estimator over a trailing window, which only ever sees the past and adapts when
the rate moves — against the best *constant* rate in hindsight (the composite
null's maximum likelihood, refit at every step):

```
Eₙ = Π qᵢ₋₁(xᵢ)  /  sup_p p^k (1−p)^{n−k}
```

Validity, in two lines: for any fixed rate p₀ in the null, `Π qᵢ₋₁(xᵢ)/p₀(xᵢ)`
is a nonnegative martingale (each factor has conditional expectation 1), and the
sup-denominator only makes Eₙ smaller — so Ville's inequality bounds the false-
alarm rate by α **over all of time, for every constant rate at once**. It is
deterministic (no randomization, unlike conformal martingales on binary data).
Measured: false alarms 0.2% against a 5% budget across three stable rates; an
abrupt regime collapse caught 100/100; the slow creep a bent metric would produce
caught 93/100.

The honest framing travels with the output: the alarm detects that the rate
**moved**, not *why*. A genuine regime change (new model, new workflow) and a
gamed metric both trip it. Its job is to force the question no dashboard asks —
*did the work change, or did the measuring get bent?*
(`src/value/drift.ts`, `test/drift.test.ts`; the "Stability" line in
`segreant roi` and the dashboard.)

## 12. Instrumentation sensitivity — which measurement moves the Index most

> **Not value of information.** VoI needs a decision, a utility model, and a
> distribution over what a measurement might reveal. This section has none of
> them: it is a sensitivity ranking of the aggregator. The decision-theoretic
> VoI lives in `src/decision/engine.ts` (§EVPI), where a scenario mixture supplies
> the probabilistic model this ranking deliberately does not have.

Missing lenses create unmeasured exposure, not a universal upper-bound theorem
(§4.4). This output reports the largest sensitivity/measurement exposure; it is
descriptive rather than an action-selection rule. For each un-instrumented lens
k, evaluate the composite with that lens hypothetically measured at a
**disclosed neutral reference** v = 0.5 (a midpoint, not a prediction):

```
Index_k(v) = 100 · exp( (Σᵢ wᵢ ln xᵢ + w_k ln v) / (Σᵢ wᵢ + w_k) )
```

and rank by the size of the move. The arithmetic is fully transparent — no
hidden priors. A heavier, further-from-current lens moves the Index more at this
reference, but the actual measured value may move it either direction. This
ranking has no acquisition-cost or utility model, so it reports exposure rather
than whether a measurement merits spending. Formal decision-theoretic VoI is a
separate calculation in `src/decision/engine.ts` (§EVPI): `valueOfInformation()`
requires posterior scenario probabilities, action utilities, and a declared
`measurementCost`, then reports gross and net utility. The two results should not
be conflated:

| Question | Answer | Section |
|---|---|---|
| Where does the next **dollar** go? | the shadow price μ | §9 |
| Which **measurement** has the largest sensitivity/measurement exposure? | instrumentation priority | §12 |
| When do I actually **know**? | the anytime-valid interval | §10 |
| Has the rate **moved**? | the drift alarm | §11 |

(`src/value/instrumentationSensitivity.ts`, `test/instrumentation-sensitivity.test.ts`; the "Largest exposure" line in
`segreant roi` / `usage`.)
