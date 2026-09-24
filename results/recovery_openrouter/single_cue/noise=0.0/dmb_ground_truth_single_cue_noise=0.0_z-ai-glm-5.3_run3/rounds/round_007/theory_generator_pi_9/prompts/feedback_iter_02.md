# feedback_iter_02

## System Prompt

You are a renowned cognitive scientist critiquing a freshly proposed candidate theory and model in the Decision Making (Binary Features) domain.

The candidate has been simulated on every previously run experiment. For each experiment you are shown the design, the metric, the value the metric takes on real data, and the value it takes on the candidate's simulated data.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

The goal of the feedback is to SURFACE theories that are EXPERIMENT-INVARIANT: that is,theories that explain data across multiple experiments. 
Your task is to determine whether the candidate captures the human/real behavior well enough across these experiments. Return a verdict:
  * "continue"   — the candidate is good enough; carry on.
  * "regenerate" — the candidate fails to capture the empirical pattern; the proposing agent must produce a new candidate, taking your rationale into account.

Justify the verdict with a concrete diagnosis (which experiments fail, in what direction, what mechanism is likely missing or miscalibrated).

## SCOPE OF YOUR CRITIQUE — STAY INSIDE THE ARBITER'S MECHANISM FAMILY
When an "## ARBITER RECOMMENDATION" block is present below, the proposer was explicitly instructed to implement the mechanism family the arbiter prescribed. Your job is to grade FIT QUALITY *within that prescribed family*, not to relitigate which family should be used — that is the arbiter's call, made one level above this loop.

Concretely:
  * If the candidate misses the data, you may push for MINOR ADJUSTMENTS that keep the prescribed mechanism intact: tightening / widening parameter ranges, adding a temperature, swapping a normalization scheme, fixing a softmax / distance metric, re-balancing attention weights, fixing a learning-rate sign, correcting a bug in the gating or recurrence, etc.
  * You MUST NOT recommend switching to a different mechanism family. Such a switch is the arbiter's prerogative; recommending it here will mislead the proposer into oscillating between families across iterations.
  * Also grade FAITHFULNESS to the recommendation explicitly: if the candidate has clearly drifted into a different family than the one prescribed, say so in the rationale and ask for a return to the prescribed family — again, with minor adjustments, not a re-design.

## ACCEPT GATE — HOW THE LOOP DECIDES WHAT TO BUILD ON NEXT
This propose-loop has a programmatic accept gate. After every iteration the candidate's `aggregate_loss` is compared against the running-best loss (`accepted_loss`):
  * `loss < accepted_loss` → ACCEPTED. The candidate becomes the new running-best base; the next iteration's proposer will build on THIS candidate.
  * `loss >= accepted_loss` → REJECTED. The base is unchanged; the next iteration's proposer will build on the SAME `accepted` candidate again, with your new feedback on top. Rejected candidates are discarded — the loop guarantees the base never regresses, so you do NOT need to ask the proposer to "revert" anything; that already happens for free.

Two consequences for your verdict:
  * If the candidate you are grading was REJECTED by the gate, returning `"continue"` is silently downgraded to `"regenerate"` (returning a worse candidate would defeat the gate). Spend your rationale on a NEW direction the proposer should try on top of the unchanged accepted base, not on defending the rejected attempt.
  * If the candidate was ACCEPTED, you can return `"continue"` to stop the loop and ship this candidate, or `"regenerate"` to keep tuning further.

## LEARN FROM YOUR OWN PAST ADVICE
When a "## YOUR PRIOR CRITIQUES" block is present below, each prior iteration ends with an "Outcome of your advice" line that says whether the next candidate the proposer produced was ACCEPTED (your advice helped — its loss strictly beat the running best) or REJECTED (your advice didn't help — the proposer discarded the result and reset to the previous accepted base). This is the loop's ground-truth signal on whether *your own previous critique was good*. Use it explicitly:
  * If a previous piece of advice was ACCEPTED, it is OK to repeat / extend it. Reinforce in the same direction.
  * If a previous piece of advice was REJECTED, do NOT repeat the same recommendation; in your new rationale, briefly acknowledge that the previous push in that direction was rejected by the gate and try a different in-family knob (or a smaller step in the same direction) instead.
  * If you find yourself oscillating (e.g. iter 1 said "increase α", iter 2 said "decrease α", iter 3 about to say "increase α" again), STOP and recommend a value between the two flanking iterations instead.
  * The "## LOSS TRAJECTORY" block at the top of the user prompt summarises the same information at the loop level — consult it before issuing a new regenerate-with-direction recommendation.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

## ARBITER RECOMMENDATION (mechanism family the proposer was told to implement)
The arbiter labelled this round's two theories in its recommendation as follows:
- THEORY 1 = `pi_7`
- THEORY 2 = `pi_8`
- The recommendation below acts on THEORY 2 (= `pi_8`).

Replace pi_8 (PRDT) with a new theory — POSITION-BRIDGED DISTRUST TALLYING (PBDT) — that keeps pi_7 as the incumbent competitor and is designed to beat it on the experiments where it is currently weak (15, 16, 13, 14) while matching it on 1, 2, 7. Architecture: (1) keep the shared, well-validated kernel: distrust inversion of stated validities with partial centering, inv_j = ((1-v_j) - c*min_k(1-v_k))^gamma / Z, but with gamma in [2.0, 2.9] — bridging the two theories' disjoint boxes [1.6,2.2] and [2.8,3.5], since Exp 1's observed contrast fell between predictions and Exp 2's ladder data sat below PGDT's steep-kernel corner predictions. (2) keep the floored convex primacy gate g_j = delta + (1-delta)*((n-j)/(n-1))^eta but make it STEEPER than either current theory: eta in [5.5, 8.0], delta in [0.12, 0.30]. This is the single most systematic residual in the pooled data: Experiments 8, 10, 11, 13, 14 and 16 all show observed values on the more-primacy side of BOTH theories' predictions (e.g., Exp 16's 13% trusted-early following vs 0.31/0.43 predicted is achievable when one early distrusted cue outweighs 2-3 later distrusted cues; Exp 13's primacy slope 0.315 vs 0.232/0.254; Exp 14's 0.540 vs 0.468/0.577). (3) replace PRDT's t0-pinned-at-zero trust ramp with a MODERATE ramp: t_j = t0 + (t1-t0)*(j/(n-1))^kappa with t0 in [0.25, 0.55] (early trusted experts retain real weight — this is what the Exp 1/2 data demand and what killed PRDT), t1 in [0.80, 1.00], kappa in [1.0, 2.5]. This preserves late-trusted recovery (Exp 15's H-family anti-primacy among 95% experts, Exp 10's final-expert overweight) without annihilating the early flat share. (4) weights combine multiplicatively as in both parents: w_j proportional to g_j * [t_j*(1-tau)/n + tau*inv_j], with tau in [0.86, 0.93] so the flat share is small enough that a steeply-gated early trusted expert cannot reach the 0.3-0.4 following rates both theories wrongly predicted on Exp 16. (5) increase response noise to fix the joint Exp 4 overshoot: beta in [3.0, 5.0], epsilon in [0.10, 0.16], so tally-vs-TTB conflict choices sit nearer the observed mild 0.158 allegiance rather than the 0.30-0.40 both theories produce. Integration and choice rule unchanged (additive d = sum_j w_j*sign(A_j - B_j), logistic in beta*d, uniform lapse). The theory's claim: the anti-validity signature is real and moderate-to-steep (bridged gamma), position structure is dominated by a steeper-than-assumed primacy gate over DISTRAUSTED cues, and trust in high-validity experts recovers with position but from a nonzero floor — a synthesis positioned to capture the experiments each parent currently wins.


## CANDIDATE THEORY
POSITION-BRIDGED DISTRUST TALLYING (PBDT), un-bundled-gate edition. Subjects scan expert ratings in presentation order through a steep floored convex primacy gate g_j = delta + (1-delta)*((n-j)/(n-1))^eta, with the gate restored to the steep end of its box (eta high, delta low) so late low-validity helper cues are crushed relative to early ones — the structural lever separating primacy-rescue trials from validity-position-confounded layouts. Stated validities are distrust-inverted (treated as error rates) via inv_j = ((1-v_j) - c*min_k(1-v_k))^gamma / Z, kept at the steep bridged range [2.6, 2.9] with a high distrust share tau, so the anti-validity gradient in confounded layouts is carried by the distrust kernel alone rather than by the gate. Trust in high-validity experts ramps with position from a small-but-nonzero floor t_j = t0 + (t1-t0)*(j/(n-1))^kappa, with a slightly concave-leaning ramp (kappa below 1) so late trusted experts recover nearly the full flat share without raising the early floor. Weights combine multiplicatively, w_j proportional to g_j * [t_j*(1-tau)/n + tau*inv_j]; evidence d = sum_j w_j*sign(A_j - B_j) is integrated additively over discriminating cues; choice is logistic in beta*d with a uniform lapse epsilon, with noise set between the two previous iterations so slope/contrast metrics that were over-attenuated recover while anchor allegiances keep their margin.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    # PBDT: Position-Bridged Distrust Tallying, UN-BUNDLED-GATE edition
    # (iter-3). Minimal-diff edit of the ACCEPTED iter-2 base per the
    # critic's iter-2 directive, which diagnosed that the iter-2 move (b)
    # had bundled an efficacious half (distrust strengthening: the Exp 3
    # win) with a counterproductive half (gate flattening: the Exp 14
    # and Exp 13 regressions). This iteration UN-BUNDLES them:
    #   (A) REVERT THE GATE FLATTENING, KEEP THE DISTRUST STRENGTHENING:
    #       eta [5.5,6.0] -> [6.5, 8.0] (steep end), delta [0.25,0.30]
    #       -> [0.15, 0.25] (low floor), while gamma stays [2.6, 2.9]
    #       and tau stays [0.91, 0.93] exactly as in iter-2. The steep
    #       gate crushes the late 50%-validity helpers on Exp 14's
    #       trusted-early side (0.350 -> toward 0.132) and restores the
    #       M/C position families on Exp 13 (1.35 -> toward 1.84);
    #       the anti-validity gradient in confounded layouts (Exp 3)
    #       is carried by the distrust kernel, which iter 2 verified.
    #   (B) PARTIALLY ROLL BACK THE NOISE: beta [3.2,4.0] -> [3.6, 4.4]
    #       and epsilon [0.13,0.16] -> [0.11, 0.14] -- between the
    #       iter-1 and iter-2 settings. Lifts the over-attenuated slope
    #       metrics (Exps 1, 11, 12, 13, 15) at a small cost on Exps
    #       4/7, which currently have margin. Exp 2 is held as a
    #       monitored constraint (structural, noise-insensitive).
    #   (C) WIDEN THE RAMP CONVEXITY DOWNWARD: kappa [1.0,1.5] ->
    #       [0.8, 1.5], a concave-leaning ramp so the late trusted
    #       expert recovers more of the flat share (Exp 8 FEDI
    #       0.294 -> toward 0.396) without touching t0, tau, or the
    #       gate. t0/t1 unchanged from iter-2.
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"PBDT expects a (2, n_features) stimulus; got shape {stim.shape}."
        )
    a, b = stim[0], stim[1]
    n = int(stim.shape[1])

    v = np.asarray(parameters["validities"], dtype=float).ravel()
    if v.shape[0] != n:
        # Graceful fallback: strictly decreasing validities.
        v = np.linspace(0.95, 0.55, n)
    v = np.clip(v, 0.0, 1.0)

    tau = float(parameters["tau"])        # distrust share of the bracket (HIGH, kept)
    eta = float(parameters["eta"])        # convexity of the primacy gate (STEEP, reverted)
    delta = float(parameters["delta"])    # floor of the primacy gate (LOW, reverted)
    gamma = float(parameters["gamma"])    # steepness of distrust inversion (kept)
    c = float(parameters["c"])           # partial centering of error rates
    t0 = float(parameters["t0"])          # trust floor at position 1 (LOW, kept)
    t1 = float(parameters["t1"])          # trust residue at the last position (HIGH, kept)
    kappa = float(parameters["kappa"])   # convexity of the trust ramp (WIDENED DOWN)
    beta = float(parameters["beta"])     # choice consistency (PARTIALLY RESTORED)
    eps = float(parameters["epsilon"])   # uniform lapse (PARTIALLY RESTORED)

    # (1) DISTRUST INVERSION with partial centering: treat the stated
    # validity as an error rate; subtract a fraction c of the smallest
    # error rate before raising to the gamma power, then normalize.
    # gamma in [2.6, 2.9] and tau in [0.91, 0.93] are preserved verbatim
    # from iter-2 -- the verified carriers of the anti-validity gradient
    # in validity-position-confounded layouts (Exp 3).
    err = 1.0 - v
    centered = np.maximum(err - c * float(err.min()), 0.0)
    inv = np.power(centered, gamma)
    Z_v = float(inv.sum())
    if Z_v > 1e-12:
        w_inv = inv / Z_v
    else:
        # Degenerate design (all validities tied at the extreme): the
        # distrust kernel is flat and position alone carries structure.
        w_inv = np.full(n, 1.0 / n)

    if n > 1:
        pos = np.arange(n, dtype=float)
        # (2) TRUST RAMP with widened-down convexity: low floor t0,
        # high t1, and kappa now allowed below 1.0 so the ramp is
        # concave-leaning -- the late trusted expert recovers more of
        # the flat share earlier in the tail (the Exp 8 FEDI lever)
        # without raising the early floor that Exp 14 needs kept low.
        t = t0 + (t1 - t0) * np.power(pos / (n - 1.0), kappa)
        # (3) PRIMACY GATE REVERTED TO THE STEEP END: eta in [6.5, 8.0]
        # with delta in [0.15, 0.25]. The steep, low-floored gate
        # concentrates attention on the first one or two experts and
        # crushes the late tail -- the structural fix for Exp 14's
        # late-helper over-weighting and Exp 13's M/C position
        # families. The anti-validity regression in confounded layouts
        # is carried by the (preserved) steep distrust kernel instead.
        g = delta + (1.0 - delta) * np.power((n - pos) / (n - 1.0), eta)
    else:
        t = np.array([1.0])
        g = np.array([1.0])

    # (4) MULTIPLICATIVE combination: the gate scales the bracket
    # cue-by-cue. tau in [0.91, 0.93] keeps the distrust channel
    # dominant; the trusted channel is carried by the ramp (small
    # early, near-full and now earlier-recovering late).
    bracket = t * (1.0 - tau) / n + tau * w_inv
    raw = g * bracket
    Z_t = float(raw.sum())
    if Z_t > 1e-12:
        w = raw / Z_t
    else:
        w = np.full(n, 1.0 / n)

    # (5) Deterministic attention: every discriminating cue is attended;
    # no capacity interference, beta is design-independent.
    s = np.sign(a - b)

    # Additive integration of all discriminating cues.
    d = float(np.dot(w, s))

    # Numerically stable logistic choice rule -- beta in [3.6, 4.4],
    # between the iter-1 and iter-2 calibrations, so the slope metrics
    # over-attenuated by iter-2's noise (Exps 1, 11, 12, 13, 15)
    # recover while Exps 4/7 keep their remaining margin.
    p_a = 0.5 * (1.0 + np.tanh(0.5 * beta * d))
    probs = np.array([p_a, 1.0 - p_a], dtype=float)

    # (6) Uniform lapse, epsilon in [0.11, 0.14]: partially rolled back
    # from iter-2's [0.13, 0.16] per the critic's split-the-difference
    # directive. Exp 2 is NOT chased with further noise -- it is held
    # as a monitored structural constraint of the distrust family.
    probs = (1.0 - eps) * probs + eps * 0.5
    return probs

`policy(probs) -> int`:
def policy(probs):
    probs = np.asarray(probs, dtype=np.float64)
    probs = probs / probs.sum()  # guard against float drift
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- tau: [0.91, 0.93]
- eta: [6.5, 8.0]
- delta: [0.15, 0.25]
- gamma: [2.6, 2.9]
- c: [0.05, 0.25]
- t0: [0.25, 0.35]
- t1: [0.95, 1.00]
- kappa: [0.8, 1.5]
- beta: [3.6, 4.4]
- epsilon: [0.11, 0.14]
- validities: validities

`rationale`:
This is a minimal-diff parameter re-balancing of the ACCEPTED iter-2 PBDT base that implements the critic's three un-bundled directives exactly, with no architectural change (the multiplicative gate-times-bracket kernel, additive integration, and logistic-lapse choice rule are preserved verbatim). The iter-2 diagnosis was that directive (b) of the previous round had bundled two moves whose effects opposed each other: the distrust strengthening (gamma/tau) delivered the Exp 3 win (-0.265 -> -0.479 vs real -0.576, variance now matching the data), while the eta-down/delta-up gate flattening was counterproductive, pushing Exp 14's trusted-early following UP (0.312 -> 0.350 vs real 0.132) by un-crushing the late 50%-validity helpers on the trusted-early side, and dropping Exp 13 (1.58 -> 1.35 vs real 1.84). (A) therefore reverts the gate to the steep end (eta [6.5, 8.0], delta [0.15, 0.25]) while freezing gamma [2.6, 2.9] and tau [0.91, 0.93] exactly at their iter-2 values: the steep gate is the only lever that structurally separates Exp 14 from Exp 3, and iter-1's steep-gate configuration already demonstrated Exp 13 values near 1.58 that the flattened iter-2 gate lost. (B) partially rolls back the global noise to between the two prior calibrations (beta [3.6, 4.4], epsilon [0.11, 0.14]): iter-2's over-attenuation cost Exps 1 (0.156 vs 0.208), 11 (0.206 vs 0.315), 12 (0.404 vs 0.540) and 15 (0.911 vs 1.036), all of which should recover, at only ~+0.01-0.02 on Exps 4/7 which currently sit with margin (0.879 vs 0.843, 0.820 vs 0.788). Exp 2 is explicitly NOT chased -- every distrust-family theory sits near 0.30 there and the critic classified it as noise-insensitive and structural, so it is held as a monitored constraint. (C) widens only the ramp's convexity downward (kappa [0.8, 1.5], slightly below the arbiter's original floor of 1.0) so the late trusted expert recovers more of the flat share earlier in the tail -- the one remaining lever for Exp 8's FEDI (0.294 -> toward 0.396) that does not conflict with (A) or (B), since it touches neither t0 (which Exp 14 needs low), tau, nor the gate. Watch-points honored: Exp 16 (0.350 vs 0.322) should not move more than ~0.05 since the steep gate acts on the same late tail that Exp 16's discriminant weights, and Exp 3's coefficient is protected by the preserved gamma/tau channel rather than by any gate re-flattening.

## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision: `loss < accepted_loss` -> ACCEPTED (becomes new base), else REJECTED (base unchanged). Use this together with the per-experiment values below to grade fit-quality AND your own past advice (see `## YOUR PRIOR CRITIQUES` below).

- iter 1: loss=0.1120 -> ACCEPTED
- iter 2: loss=0.1011 -> ACCEPTED
- iter 3 (current candidate you are grading): loss=0.0955 -> ACCEPTED
Running-best (last accepted) base: iter 3 at loss=0.0955.

## EXPERIMENTAL RESULTS (candidate vs real, per experiment)
### Experiment 1
**Design**
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 0, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 0]  B=[1, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[1, 1, 0, 1, 1]
  A=[1, 1, 0, 1, 1]  B=[1, 1, 1, 0, 0]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    # Design validities (fixed by experiment): strictly decreasing,
    # so the TTB cue order is simply feature 0,1,2,3,4.
    validities = np.array([0.95, 0.85, 0.75, 0.65, 0.5])
    cue_order = np.argsort(-validities, kind="stable")

    def _to_vec(x):
        if isinstance(x, str):
            return np.array(
                [int(v) for v in x.strip("[]()").replace(",", " ").split()]
            )
        return np.asarray(x, dtype=float)

    hits = []
    a_col = data["option_a_ratings"].tolist()
    b_col = data["option_b_ratings"].tolist()
    r_col = data["response"].tolist()

    for a_cell, b_cell, resp in zip(a_col, b_col, r_col):
        a = _to_vec(a_cell)
        b = _to_vec(b_cell)
        if a.size == 0 or a.shape != b.shape:
            continue

        # --- TTB winner: first discriminating cue in validity order ---
        ttb_winner = None
        for j in cue_order:
            if j >= a.size:
                continue
            if a[j] > b[j]:
                ttb_winner = 0
                break
            if b[j] > a[j]:
                ttb_winner = 1
                break
        if ttb_winner is None:
            continue  # no discriminating cue: TTB guesses, uninformative

        # --- Tallying winner: strict feature-wise win counts ---
        a_wins = int(np.sum(a > b))
        b_wins = int(np.sum(b > a))
        if a_wins == b_wins:
            continue  # tally ties -> Tallying guesses at 0.5, dilutes contrast
        tally_winner = 0 if a_wins > b_wins else 1

        if tally_winner == ttb_winner:
            continue  # heuristics agree: uninformative

        # Pure conflict trial: TTB's option vs the tally majority's option.
        hits.append(1.0 if int(resp) == ttb_winner else 0.0)

    if not hits:
        return 0.5
    return float(np.mean(hits))
```

**Observed (real) value:** 0.2080 (var=0.0060)
**Candidate trajectory (this loop):**
  - iter 1: 0.1897 (var=0.0040) (Δ vs real -0.0183)
  - iter 2: 0.1557 (var=0.0030) (Δ vs real -0.0523)
  - iter 3 (current): 0.1600 (var=0.0021) (Δ vs real -0.0480)
**Other theories' values on this metric (for reference):**
- pi_1: 0.8443 (var=0.0128)
- pi_2: 0.1357 (var=0.0112)
- pi_3: 0.2377 (var=0.0050)
- pi_4: 0.2197 (var=0.0050)
- pi_5: 0.1807 (var=0.0022)
- pi_5_1: 0.1870 (var=0.0059)
- pi_6: 0.1750 (var=0.0040)
- pi_7: 0.1637 (var=0.0053)
- pi_8: 0.1093 (var=0.0009)

### Experiment 2
**Design**
  A=[0, 1, 0, 0, 1, 1]  B=[0, 0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 0, 1]  B=[0, 1, 0, 0, 1, 0]
  A=[0, 0, 1, 1, 0, 0]  B=[0, 1, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 1, 0]  B=[0, 0, 1, 1, 0, 1]
  A=[1, 0, 0, 1, 1, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1]  B=[0, 0, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 1, 0]  B=[0, 1, 1, 1, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Tally-vs-TTB choice-allegiance contrast.

    For every trial we determine (i) the TALLYING winner (option with more
    strict feature-wise wins) and (ii) the TAKE-THE-BEST winner (winner on
    the highest-validity discriminating cue, validities fixed by design as
    [0.95, 0.9, 0.85, 0.65, 0.6, 0.5]).  The metric is

        mean( response == tally winner ) - mean( response == TTB winner )

    On the 4 trial types where both heuristics pick the same option
    (trials 1, 3, 5, 7 and mirrors) the two indicators are identical and
    cancel.  On the 12 conflict trial types they are exact complements, so
    the metric reduces to 0.75 * (2*P(tally winner | conflict) - 1): strongly
    positive under Tallying, strongly negative under TTB.
    """
    validities = np.array([0.95, 0.9, 0.85, 0.65, 0.6, 0.5])
    cue_order = np.argsort(-validities, kind="stable")

    a_col = data["option_a_ratings"].tolist()
    b_col = data["option_b_ratings"].tolist()
    r_col = data["response"].tolist()

    tally_match = []
    ttb_match = []

    for ca, cb, cr in zip(a_col, b_col, r_col):
        a = np.asarray(ca, dtype=float).ravel()
        b = np.asarray(cb, dtype=float).ravel()
        r = int(cr)

        # Tallying winner: more strict feature-wise wins (ties on a feature
        # contribute to neither side).
        a_wins = float(np.sum(a > b))
        b_wins = float(np.sum(b > a))
        if a_wins > b_wins:
            tally_winner = 0
        elif b_wins > a_wins:
            tally_winner = 1
        else:
            tally_winner = -1  # undiscriminating tally -> excluded

        # TTB winner: first discriminating cue in descending-validity order.
        ttb_winner = -1
        for j in cue_order:
            if a[j] > b[j]:
                ttb_winner = 0
                break
            if b[j] > a[j]:
                ttb_winner = 1
                break

        if tally_winner >= 0:
            tally_match.append(1.0 if r == tally_winner else 0.0)
        if ttb_winner >= 0:
            ttb_match.append(1.0 if r == ttb_winner else 0.0)

    if len(tally_match) == 0 or len(ttb_match) == 0:
        return 0.0

    return float(np.mean(tally_match) - np.mean(ttb_match))
```

**Observed (real) value:** 0.1583 (var=0.0053)
**Candidate trajectory (this loop):**
  - iter 1: 0.3088 (var=0.0055) (Δ vs real +0.1504)
  - iter 2: 0.2988 (var=0.0055) (Δ vs real +0.1404)
  - iter 3 (current): 0.3179 (var=0.0047) (Δ vs real +0.1596)
**Other theories' values on this metric (for reference):**
- pi_2: 0.5479 (var=0.0187)
- pi_1: -0.4837 (var=0.0228)
- pi_3: 0.1658 (var=0.0093)
- pi_4: 0.2079 (var=0.0051)
- pi_5: 0.2308 (var=0.0086)
- pi_5_1: 0.2875 (var=0.0062)
- pi_6: 0.2408 (var=0.0082)
- pi_7: 0.2996 (var=0.0066)
- pi_8: 0.4033 (var=0.0047)

### Experiment 3
**Design**
  A=[1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[1, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  A=[1, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 1]
  A=[0, 1, 1, 0, 1]  B=[1, 0, 0, 1, 0]
  A=[0, 1, 0, 1, 1]  B=[1, 0, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 1]  B=[1, 0, 0, 1, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[0, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 1]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 1, 0, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 0]  B=[1, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1]

**Metric**
```python
import numpy as np
import pandas as pd


def _to_vec(x):
    """Robustly convert a cell (list/tuple/ndarray/str) to a float 1-D array."""
    if isinstance(x, np.ndarray):
        return x.astype(float)
    if isinstance(x, (list, tuple)):
        return np.asarray(list(x), dtype=float)
    s = str(x).strip().replace("[", " ").replace("]", " ").replace(",", " ")
    return np.asarray(s.split(), dtype=float)


def metric(data: pd.DataFrame) -> float:
    df = data.reset_index(drop=True)
    n_rows = len(df)
    if n_rows == 0:
        return 0.0

    A = np.vstack([_to_vec(x) for x in df["option_a_ratings"]])
    B = np.vstack([_to_vec(x) for x in df["option_b_ratings"]])
    n_feat = A.shape[1]

    # Design validities [0.95, 0.85, 0.75, 0.65, 0.60]; fall back gracefully.
    v = np.array([0.95, 0.85, 0.75, 0.65, 0.60], dtype=float)
    if v.shape[0] != n_feat:
        v = np.linspace(0.95, 0.60, n_feat)

    # Chose-A indicator (response: 0 = A, 1 = B).
    y = (np.asarray(df["response"], dtype=float) == 0.0).astype(float)

    a_win = A > B
    b_win = B > A

    # Signed tally margin (Tallying's ONLY explanatory variable).
    margin = a_win.sum(axis=1).astype(float) - b_win.sum(axis=1).astype(float)

    # Validity-weighted evidence difference (NVW's driving quantity).
    d = (a_win * v).sum(axis=1) - (b_win * v).sum(axis=1)

    # OLS: y ~ 1 + margin + d. Return the partial coefficient on d.
    X = np.column_stack([np.ones(n_rows), margin, d])
    beta, _, _, _ = np.linalg.lstsq(X, y, rcond=None)
    return float(beta[2])
```

**Observed (real) value:** -0.5756 (var=0.0186)
**Candidate trajectory (this loop):**
  - iter 1: -0.2651 (var=0.0420) (Δ vs real +0.3105)
  - iter 2: -0.4785 (var=0.0138) (Δ vs real +0.0971)
  - iter 3 (current): -0.4461 (var=0.0167) (Δ vs real +0.1295)
**Other theories' values on this metric (for reference):**
- pi_3: 0.2763 (var=0.0165)
- pi_2: -0.0069 (var=0.0141)
- pi_1: 0.7613 (var=0.0601)
- pi_4: -0.4120 (var=0.0294)
- pi_5: -0.5397 (var=0.0203)
- pi_5_1: -0.5621 (var=0.0241)
- pi_6: -0.4702 (var=0.0232)
- pi_7: -0.4381 (var=0.0264)
- pi_8: -0.4835 (var=0.0191)

### Experiment 4
**Design**
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 0, 0]  B=[1, 1, 1, 1, 1, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 0]  B=[1, 1, 1, 1, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 0, 1, 1, 0]  B=[0, 1, 1, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 0, 1, 0, 1, 0]
  A=[0, 1, 1, 0, 0, 0, 1, 1]  B=[1, 0, 0, 1, 1, 1, 0, 0]
  A=[1, 0, 0, 1, 1, 1, 0, 0]  B=[0, 1, 1, 0, 0, 0, 1, 1]
  A=[1, 1, 1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Anchor-allegiance: proportion of trials with a large tally margin
    (|a_wins - b_wins| >= 6) on which the subject chose the option that
    wins on more features (the tally winner).

    Under Tallying, these are the unambiguous anchors (8-0 and 7-1 splits:
    design trials 7, 8, 21, 22, 23, 24 and their 4 repetitions = 24 trials
    per subject), where the softmax over tallies predicts near-deterministic
    choice for any non-trivial beta. Under NVW, the capacity-interference
    factor delta^4 crushes the effective inverse temperature to
    beta_eff <= 11 * 0.30^4 ~ 0.09, so even the maximum validity-weighted
    evidence difference (~6) yields P ~ sigmoid(0.5) <= 0.64; attention
    lapses and the uniform-mixing epsilon only pull this further toward
    0.5. The two theories therefore make sharply separated predictions on
    this proportion, and the A/B-mirrored anchors cancel side bias.
    """
    a_col = data['option_a_ratings']
    b_col = data['option_b_ratings']
    r_col = data['response']

    n_anchor = 0
    n_hit = 0

    for ra, rb, resp in zip(a_col, b_col, r_col):
        va = np.asarray(ra, dtype=float)
        vb = np.asarray(rb, dtype=float)
        if va.shape != vb.shape:
            continue

        a_wins = float(np.sum(va > vb))
        b_wins = float(np.sum(vb > va))
        margin = a_wins - b_wins

        if abs(margin) >= 6:
            n_anchor += 1
            winner_is_a = margin > 0
            chose_a = (int(resp) == 0)
            if chose_a == winner_is_a:
                n_hit += 1

    if n_anchor == 0:
        return 0.5
    return float(n_hit) / float(n_anchor)

```

**Observed (real) value:** 0.8433 (var=0.0152)
**Candidate trajectory (this loop):**
  - iter 1: 0.8925 (var=0.0043) (Δ vs real +0.0492)
  - iter 2: 0.8792 (var=0.0037) (Δ vs real +0.0358)
  - iter 3 (current): 0.8858 (var=0.0037) (Δ vs real +0.0425)
**Other theories' values on this metric (for reference):**
- pi_2: 0.8808 (var=0.0089)
- pi_3: 0.5300 (var=0.0122)
- pi_1: 0.6133 (var=0.0060)
- pi_4: 0.8133 (var=0.0065)
- pi_5: 0.8083 (var=0.0061)
- pi_5_1: 0.8217 (var=0.0065)
- pi_6: 0.9058 (var=0.0060)
- pi_7: 0.8925 (var=0.0035)
- pi_8: 0.9133 (var=0.0028)

### Experiment 5
**Design**
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 1, 1]  B=[0, 1, 1, 1, 0, 0]
  A=[0, 1, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Validity-adherence rate on VALIDITY-vs-RECENCY conflict trials.
    #
    # For every trial we compute two decision variables from the presented
    # cue patterns:
    #   d_v = sum_j v_j * sign(A_j - B_j)   (validity-weighted evidence for A)
    #   d_r = sum_j (j/(n-1))^3 * sign(A_j - B_j)  (convex cue-order recency
    #                                              evidence for A)
    # A trial is a CONFLICT trial when the two point in opposite directions
    # and both are non-trivial in magnitude. On those trials the metric is
    # the proportion of choices that follow the VALIDITY-implied option.
    #
    # NVW (validity-weighted integration) predicts adherence clearly above
    # chance (~0.6); SWC (recency-dominated subjective weights) predicts
    # adherence well below chance (~0.3), because on these trials its
    # recency gradient favors the opposite option.

    validities = np.array([0.95, 0.90, 0.85, 0.62, 0.50, 0.50], dtype=float)
    n = int(validities.shape[0])
    # Convex recency profile over presentation positions (eta ~ 3).
    recency = (np.arange(n, dtype=float) / float(n - 1)) ** 3.0

    a_col = data["option_a_ratings"]
    b_col = data["option_b_ratings"]
    r_col = data["response"]

    hits = []
    for a_raw, b_raw, resp in zip(a_col, b_col, r_col):
        a = np.asarray(a_raw, dtype=float).ravel()
        b = np.asarray(b_raw, dtype=float).ravel()
        if a.shape[0] != n or b.shape[0] != n:
            continue
        s = np.sign(a - b)
        if not np.any(s != 0):
            continue

        d_v = float(np.dot(validities, s))
        d_r = float(np.dot(recency, s))

        # Need a real conflict with non-trivial evidence on both axes.
        if abs(d_v) < 0.30 or abs(d_r) < 0.50:
            continue
        if np.sign(d_v) == np.sign(d_r):
            continue

        validity_winner_is_a = (d_v > 0.0)
        chose_a = (int(resp) == 0)
        hits.append(1.0 if (chose_a == validity_winner_is_a) else 0.0)

    if len(hits) == 0:
        return 0.0
    return float(np.mean(hits))
```

**Observed (real) value:** 0.2313 (var=0.0046)
**Candidate trajectory (this loop):**
  - iter 1: 0.2822 (var=0.0067) (Δ vs real +0.0509)
  - iter 2: 0.2253 (var=0.0037) (Δ vs real -0.0059)
  - iter 3 (current): 0.2209 (var=0.0026) (Δ vs real -0.0103)
**Other theories' values on this metric (for reference):**
- pi_3: 0.5988 (var=0.0039)
- pi_4: 0.2816 (var=0.0052)
- pi_1: 0.7519 (var=0.0061)
- pi_2: 0.5803 (var=0.0046)
- pi_5: 0.2544 (var=0.0025)
- pi_5_1: 0.2369 (var=0.0070)
- pi_6: 0.2559 (var=0.0082)
- pi_7: 0.2334 (var=0.0055)
- pi_8: 0.1841 (var=0.0032)

### Experiment 6
**Design**
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 1, 0, 0]  B=[1, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 1, 0]  B=[1, 0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 1, 0]  B=[0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1]  B=[0, 1, 0, 1, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 1, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 1, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 1, 1, 1, 1, 0]
  A=[0, 0, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 1, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0, 0]
  A=[1, 1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Recency-consistency rate: fraction of choices aligned with a convex
    # cue-order recency gradient, restricted to trials where that gradient
    # is strong and its direction is unambiguous across SWC's eta range.
    #
    # SWC (advocated): late cues dominate via convex recency -> rate well
    #   above 0.5 (predicted ~0.65-0.85 across its parameter box).
    # NVW (competing): validity-weighted integration with capacity
    #   interference (beta_eff = beta*delta^3 <= ~0.30 at n=7) -> choices
    #   near chance on nearly every trial, and anti-recency or neutral on
    #   the conflict trials -> rate ~0.50.
    df = data.reset_index(drop=True)
    if len(df) == 0:
        return 0.5

    a_arrs = [np.asarray(list(x), dtype=float) for x in df['option_a_ratings']]
    b_arrs = [np.asarray(list(x), dtype=float) for x in df['option_b_ratings']]
    resp = pd.to_numeric(df['response'], errors='coerce').to_numpy()

    if len(a_arrs) == 0 or a_arrs[0].ndim != 1:
        return 0.5
    n = int(a_arrs[0].shape[0])
    if n < 2:
        return 0.5

    pos = np.arange(n, dtype=float) / (n - 1.0)
    w_lo = pos ** 2.5   # SWC's eta lower corner
    w_mid = pos ** 3.5  # SWC's eta midpoint
    w_hi = pos ** 4.5   # SWC's eta upper corner

    consistent = []
    for a, b, r in zip(a_arrs, b_arrs, resp):
        if a.shape[0] != n or b.shape[0] != n:
            continue
        if not np.isfinite(r):
            continue
        s = np.sign(a - b)
        if not np.any(s != 0):
            continue
        e_lo = float(np.dot(w_lo, s))
        e_mid = float(np.dot(w_mid, s))
        e_hi = float(np.dot(w_hi, s))
        # Require the recency gradient's direction to be invariant across
        # SWC's whole eta range (drops ambiguous trials, e.g. 1 late cue vs
        # 4 mid cues, where the sign flips with eta).
        if e_lo == 0.0 or e_hi == 0.0 or np.sign(e_lo) != np.sign(e_hi):
            continue
        # Require non-trivial gradient magnitude (drops near-degenerate
        # trials where even SWC predicts ~0.52).
        if abs(e_mid) < 0.25:
            continue
        fav_a = e_mid > 0.0
        chose_a = (int(r) == 0)  # response: 0 = chose A, 1 = chose B
        consistent.append(1.0 if (chose_a == fav_a) else 0.0)

    if len(consistent) == 0:
        return 0.5
    return float(np.mean(consistent))
```

**Observed (real) value:** 0.3739 (var=0.0026)
**Candidate trajectory (this loop):**
  - iter 1: 0.3244 (var=0.0032) (Δ vs real -0.0494)
  - iter 2: 0.3303 (var=0.0025) (Δ vs real -0.0436)
  - iter 3 (current): 0.3217 (var=0.0024) (Δ vs real -0.0522)
**Other theories' values on this metric (for reference):**
- pi_4: 0.7261 (var=0.0028)
- pi_3: 0.4847 (var=0.0034)
- pi_1: 0.3794 (var=0.0022)
- pi_2: 0.3853 (var=0.0032)
- pi_5: 0.4408 (var=0.0038)
- pi_5_1: 0.4392 (var=0.0036)
- pi_6: 0.3361 (var=0.0034)
- pi_7: 0.3028 (var=0.0052)
- pi_8: 0.3092 (var=0.0025)

### Experiment 7
**Design**
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 0, 1, 0, 1, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 1, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 0, 1, 0]
  A=[0, 1, 0, 1, 0, 0]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """Anti-validity vs. recency disagreement score.

    On trials where IVC's distrust-inverted weights and SWC's recency-dominated
    weights point to OPPOSITE options, report the proportion of choices that
    follow the IVC-preferred option. IVC-simulated data -> well above 0.5;
    SWC-simulated data -> well below 0.5.
    """
    data = data.reset_index(drop=True)
    if len(data) == 0:
        return 0.5

    # Build stimulus matrices without hashing any list-valued cells.
    a = np.vstack([np.asarray(r, dtype=float) for r in data["option_a_ratings"]])
    b = np.vstack([np.asarray(r, dtype=float) for r in data["option_b_ratings"]])
    n = a.shape[1]

    # Design validities (fallback mirrors both theories' graceful degradation).
    v = np.array([0.5, 0.9, 0.6, 0.95, 0.5, 0.6], dtype=float)
    if v.shape[0] != n:
        v = np.linspace(0.95, 0.55, n)

    # --- IVC weights at mid-range parameters (tau=0.925, kappa=2.7) ---
    tau, kappa = 0.925, 2.7
    inv = np.power(1.0 - v, kappa)
    Z = float(inv.sum())
    w_inv = inv / Z if Z > 1e-12 else np.full(n, 1.0 / n)
    w_ivc = (1.0 - tau) / n + tau * w_inv

    # --- SWC weights at mid-range parameters (lam=0.9, rho=0.9, eta=3.5) ---
    lam, rho, eta = 0.9, 0.9, 3.5
    vspan = float(v.max() - v.min())
    if vspan > 1e-12:
        vnorm = (v - v.min()) / vspan
    else:
        vnorm = np.full(n, 0.5)
    if n > 1:
        pos = (np.arange(n, dtype=float) / (n - 1.0)) ** eta
    else:
        pos = np.full(n, 0.5)
    g = (1.0 - rho) * vnorm + rho * pos
    w_swc = (1.0 - lam) / n + lam * g

    # Signed discriminating-cue vector per trial.
    s = np.sign(a - b)
    d_ivc = s @ w_ivc
    d_swc = s @ w_swc

    # Keep only trials where the two theories STRICTLY disagree in sign.
    # (d_ivc == 0, e.g. the validity-matched EQ trials, is excluded.)
    mask = (d_ivc * d_swc) < 0.0
    if not np.any(mask):
        return 0.5

    resp = np.asarray(data["response"].to_numpy())
    r = resp[mask]
    ivc_prefers_a = d_ivc[mask] > 0.0
    chose_ivc_preferred = np.where(ivc_prefers_a, r == 0, r == 1)
    return float(chose_ivc_preferred.mean())
```

**Observed (real) value:** 0.7878 (var=0.0086)
**Candidate trajectory (this loop):**
  - iter 1: 0.8522 (var=0.0030) (Δ vs real +0.0644)
  - iter 2: 0.8200 (var=0.0030) (Δ vs real +0.0322)
  - iter 3 (current): 0.8511 (var=0.0024) (Δ vs real +0.0633)
**Other theories' values on this metric (for reference):**
- pi_5: 0.6389 (var=0.0060)
- pi_4: 0.3622 (var=0.0067)
- pi_1: 0.1533 (var=0.0097)
- pi_2: 0.5167 (var=0.0064)
- pi_3: 0.4511 (var=0.0081)
- pi_5_1: 0.6478 (var=0.0070)
- pi_6: 0.7750 (var=0.0124)
- pi_7: 0.8439 (var=0.0041)
- pi_8: 0.8472 (var=0.0044)

### Experiment 8
**Design**
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 1, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    """Final-Expert Dominance Index (FEDI).

    Among trials where the LAST-presented expert (feature position n-1) is the
    ONLY cue favoring one option (i.e., that option's rating vector is all
    zeros except a 1 in the final position), compute the proportion of
    choices that follow the final expert's recommendation.

    A convex-recency weighting (SWC) predicts adherence well above 0.5
    (the last cue carries the largest subjective weight at every corner of
    its parameter box). A distrust-inverted validity weighting (IVC)
    predicts adherence below 0.5, because the final expert here has a high
    stated validity (0.90) and is therefore heavily discounted.
    """
    df = data.reset_index(drop=True)

    A = np.array(
        [list(map(int, x)) for x in df['option_a_ratings']], dtype=int
    )
    B = np.array(
        [list(map(int, x)) for x in df['option_b_ratings']], dtype=int
    )
    r = df['response'].to_numpy(dtype=int)

    if A.ndim != 2 or A.shape[0] == 0:
        return float('nan')

    n_feat = A.shape[1]
    last = n_feat - 1

    a_last = A[:, last]
    b_last = B[:, last]

    # Last expert discriminates between the options.
    disc = a_last != b_last

    # The option endorsed by the final expert wins ONLY that final cue
    # (its rating vector sums to 1). This selects the single-cue and
    # multi-cue 'ladder' duels against the last expert (trials 1-14 and
    # their mirrors) and excludes trials where the last-cue option also
    # wins other cues.
    a_sel = disc & (a_last == 1) & (A.sum(axis=1) == 1)
    b_sel = disc & (b_last == 1) & (B.sum(axis=1) == 1)
    sel = a_sel | b_sel

    if not np.any(sel):
        return float('nan')

    # response: 0 = chose A, 1 = chose B.
    # Did the subject follow the final expert's endorsed option?
    followed = np.where(a_sel[sel], r[sel] == 0, r[sel] == 1)

    return float(np.mean(followed))
```

**Observed (real) value:** 0.3957 (var=0.0045)
**Candidate trajectory (this loop):**
  - iter 1: 0.2700 (var=0.0026) (Δ vs real -0.1257)
  - iter 2: 0.2943 (var=0.0023) (Δ vs real -0.1014)
  - iter 3 (current): 0.2804 (var=0.0028) (Δ vs real -0.1154)
**Other theories' values on this metric (for reference):**
- pi_4: 0.6796 (var=0.0044)
- pi_5: 0.3561 (var=0.0033)
- pi_1: 0.5529 (var=0.0024)
- pi_2: 0.4039 (var=0.0053)
- pi_3: 0.4300 (var=0.0036)
- pi_5_1: 0.3393 (var=0.0058)
- pi_6: 0.2818 (var=0.0035)
- pi_7: 0.2832 (var=0.0037)
- pi_8: 0.2654 (var=0.0024)

### Experiment 9
**Design**
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 1, 1, 1, 1, 0]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Recency-following rate on count-neutral trials.
    #
    # With all six validities equal (0.95), IVC's weight vector is EXACTLY
    # flat for every admissible parameter combination (the distrust kernel
    # is constant across features, so w_j = 1/n identically). Hence on any
    # trial where the two options win an equal number of discriminating
    # cues (count difference = 0), IVC's evidence d = 0 and P(choose A) =
    # 0.50 exactly -- the lapse preserves 0.5. This is parameter-free.
    #
    # SWC, in contrast, has strictly increasing weights in cue position
    # (lambda >= 0.8, rho >= 0.8, convex recency), and on count-neutral
    # trials its evidence reduces EXACTLY to d = lambda*rho*sum_j pos_j*s_j,
    # so it must prefer the option supported by the LATER cues, with
    # subject-level choice rates roughly in [0.60, 0.79].
    #
    # The metric: among count-neutral trials, the fraction of choices that
    # go to the option favored by the later (more recent) discriminating
    # cues. IVC -> 0.50 for every subject; SWC -> well above 0.50.

    def _mat(col):
        return np.array(
            [np.asarray(v, dtype=float).ravel() for v in list(col)],
            dtype=float,
        )

    A = _mat(data['option_a_ratings'])
    B = _mat(data['option_b_ratings'])
    resp = np.asarray(pd.Series(data['response']).to_numpy(), dtype=float)

    if A.size == 0 or A.ndim != 2 or A.shape[0] == 0 or B.shape[0] != A.shape[0]:
        return 0.5
    n = int(A.shape[1])
    if n < 2:
        return 0.5

    # Convex recency profile over cue positions (any strictly increasing
    # profile gives the same favored direction on count-neutral trials;
    # 3.5 matches SWC's mid-gradient). Direction is what matters here.
    pos = (np.arange(n, dtype=float) / (n - 1.0)) ** 3.5

    S = np.sign(A - B)            # +1: cue favors A, -1: favors B, 0: tie
    count = S.sum(axis=1)         # IVC's evidence direction (flat weights)
    rec = S @ pos                 # recency evidence for A

    neutral = (np.abs(count) < 1e-9) & (np.abs(rec) > 1e-9)
    if not np.any(neutral):
        return 0.5

    chose_a = resp[neutral] == 0
    fav_a = rec[neutral] > 0      # option supported by the later cues
    followed = np.where(fav_a, chose_a, ~chose_a)
    return float(np.mean(followed))
```

**Observed (real) value:** 0.3414 (var=0.0042)
**Candidate trajectory (this loop):**
  - iter 1: 0.2993 (var=0.0051) (Δ vs real -0.0421)
  - iter 2: 0.3318 (var=0.0036) (Δ vs real -0.0096)
  - iter 3 (current): 0.2914 (var=0.0032) (Δ vs real -0.0500)
**Other theories' values on this metric (for reference):**
- pi_5_1: 0.5043 (var=0.0036)
- pi_4: 0.6693 (var=0.0058)
- pi_1: 0.1557 (var=0.0121)
- pi_2: 0.4986 (var=0.0044)
- pi_3: 0.4986 (var=0.0040)
- pi_5: 0.5043 (var=0.0045)
- pi_6: 0.4118 (var=0.0064)
- pi_7: 0.2989 (var=0.0035)
- pi_8: 0.2936 (var=0.0038)

### Experiment 10
**Design**
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[0, 0, 0, 1, 0, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 0, 1]
  A=[0, 0, 1, 0, 0, 1]  B=[1, 0, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1, 0]
  A=[0, 1, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    # Recency-gradient choice score on theory-divergent trials.
    #
    # Design validities: experts at positions 1 and 4 (0-indexed 0 and 3)
    # have validity 0.95; the other four experts have validity 0.75.
    #
    # Per trial:
    #   s_j = sign(A_j - B_j)   which option expert j favors
    #   x   = sum_j p_j * s_j   recency evidence for A, with convex
    #                           position weights p_j = (j/5)^3.5
    #   y   = +1 if A chosen, -1 if B chosen
    #
    # Scored trial families (48 of the 96 trials per subject):
    # (1) VALIDITY-MATCHED trials (types 3/4, 9/10, 13/14, 17/18, 25/26
    #     plus mirrors): the two options' discriminating experts carry
    #     identical validity multisets. Any validity-only weighting (IVC)
    #     yields exactly zero evidence, so E[x*y] = 0 for EVERY parameter
    #     combination (the uniform lapse preserves 0.5). SWC's convex
    #     recency gradient makes E[x*y] strongly positive.
    # (2) VALIDITY-CONFOUNDED trials (types 5/6, 11/12, 23/24 plus
    #     mirrors): the option whose experts sit LATER also carries
    #     strictly more 0.95 experts. IVC's distrust inversion favors
    #     the EARLY option, so E[x*y] < 0; SWC's recency gradient still
    #     favors the LATE option, so E[x*y] > 0.
    #
    # Metric = mean of x*y over these trials.
    # SWC: strongly positive (~ +0.28 across its box, range ~ +0.17..+0.41).
    # IVC: zero on the matched family for all parameters, slightly
    # negative overall (~ -0.03).

    n = 6
    V = np.array([0.95, 0.75, 0.75, 0.95, 0.75, 0.75])
    P = (np.arange(n, dtype=float) / float(n - 1)) ** 3.5
    hi = V >= 0.9

    def to_arr(cell):
        if isinstance(cell, np.ndarray):
            return np.asarray(cell, dtype=float).ravel()
        if isinstance(cell, (list, tuple)):
            return np.asarray(list(cell), dtype=float).ravel()
        txt = str(cell).strip().strip('[]()')
        parts = txt.replace(',', ' ').split()
        return np.asarray([float(t) for t in parts], dtype=float).ravel()

    a_cells = data['option_a_ratings'].tolist()
    b_cells = data['option_b_ratings'].tolist()
    r_cells = data['response'].tolist()

    scores = []
    for i in range(len(a_cells)):
        try:
            a = to_arr(a_cells[i])
            b = to_arr(b_cells[i])
        except Exception:
            continue
        if a.shape[0] != n or b.shape[0] != n:
            continue
        try:
            resp = int(r_cells[i])
        except Exception:
            continue
        if resp != 0 and resp != 1:
            continue

        s = np.sign(a - b)
        ia = np.where(s > 0)[0]
        ib = np.where(s < 0)[0]
        if ia.size == 0 or ib.size == 0:
            continue

        va = sorted(V[ia].tolist())
        vb = sorted(V[ib].tolist())
        matched = (va == vb)

        x = float(np.dot(P, s))
        if not matched:
            if x == 0:
                continue
            late_a = x > 0
            late_hi = int(hi[ia].sum()) if late_a else int(hi[ib].sum())
            early_hi = int(hi[ib].sum()) if late_a else int(hi[ia].sum())
            if late_hi <= early_hi:
                continue

        y = 1.0 if resp == 0 else -1.0
        scores.append(x * y)

    if len(scores) == 0:
        return 0.0
    return float(np.mean(scores))
```

**Observed (real) value:** -0.1729 (var=0.0118)
**Candidate trajectory (this loop):**
  - iter 1: -0.2429 (var=0.0069) (Δ vs real -0.0700)
  - iter 2: -0.1873 (var=0.0125) (Δ vs real -0.0145)
  - iter 3 (current): -0.2368 (var=0.0107) (Δ vs real -0.0639)
**Other theories' values on this metric (for reference):**
- pi_4: 0.2647 (var=0.0159)
- pi_5_1: -0.0459 (var=0.0117)
- pi_1: -0.3350 (var=0.0112)
- pi_2: 0.0242 (var=0.0128)
- pi_3: 0.0443 (var=0.0150)
- pi_5: -0.0563 (var=0.0178)
- pi_6: -0.2233 (var=0.0216)
- pi_7: -0.2325 (var=0.0136)
- pi_8: -0.2524 (var=0.0104)

### Experiment 11
**Design**
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 1, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[0, 0, 1, 0, 1, 0]  B=[1, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 1, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 1, 0, 1, 1]  B=[1, 1, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 1, 0, 1, 0, 0]  B=[0, 0, 1, 0, 1, 1]
  A=[0, 1, 1, 0, 1, 0]  B=[1, 0, 0, 1, 0, 1]
  A=[1, 0, 0, 1, 0, 1]  B=[0, 1, 1, 0, 1, 0]
  A=[1, 0, 0, 1, 0, 1]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 0, 0, 1, 0, 1]

**Metric**
```python
import numpy as np
import pandas as pd

def metric(data: pd.DataFrame) -> float:
    # Within-allegiance-cell OLS slope of choice on reference primacy evidence.
    #
    # Identification: group every trial by (c1, c2) where
    #   c1 = number of 0.60-expert wins for A minus for B (positions 2,3,5),
    #   c2 = total signed cue count.
    # Any position-INVARIANT validity-weighted model (IVC at ANY parameter
    # combo, plain tallying, any lapse/transform) makes P(choose A) a function
    # of (c1, c2) ONLY. Demeaning the primacy regressor within these cells
    # therefore makes the population OLS slope EXACTLY 0 under IVC,
    # parameter-free, for every subject. PW-IVC's primacy gradient breaks the
    # cell-conditional independence, producing a strictly positive slope.

    ratings_a = data['option_a_ratings']
    ratings_b = data['option_b_ratings']
    A = np.array([np.asarray(r, dtype=float) for r in ratings_a], dtype=float)
    B = np.array([np.asarray(r, dtype=float) for r in ratings_b], dtype=float)
    if A.ndim != 2 or A.shape[0] == 0:
        return 0.0
    n = A.shape[1]

    # Reference primacy kernel, eta = 5 (middle of PW-IVC's eta range [3.5, 6.5]).
    if n > 1:
        pos = np.arange(n, dtype=float)
        wp = ((n - pos) / (n - 1.0)) ** 5.0
        wp = wp / wp.sum()
    else:
        wp = np.ones(1)

    S = np.sign(A - B)
    y = 1.0 - np.asarray(data['response'], dtype=float)  # 1 = chose A

    x1 = S.dot(wp)  # primacy evidence favoring A

    # Allegiance cell for this design: validities [0.95, 0.6, 0.6, 0.95, 0.6, 0.95]
    # -> 0.60 experts at 0-indexed positions 1, 2, 4.
    if n == 6:
        c1 = S[:, 1] + S[:, 2] + S[:, 4]
    else:
        c1 = np.zeros(A.shape[0])
    c2 = S.sum(axis=1)

    g = c1.astype(int).astype(str) + "_" + c2.astype(int).astype(str)
    df = pd.DataFrame({'x1': x1, 'y': y, 'g': g})

    # Demean primacy evidence within allegiance cell: removes ALL validity-based
    # mean structure (distrust kernel at any gamma/c/tau, flat counting, lapse).
    df['x1c'] = df['x1'] - df.groupby('g')['x1'].transform('mean')
    ssx = float((df['x1c'] ** 2).sum())
    if ssx <= 1e-12:
        return 0.0
    ybar = float(df['y'].mean())
    slope = float((df['x1c'] * (df['y'] - ybar)).sum() / ssx)
    return slope
```

**Observed (real) value:** 0.3148 (var=0.0095)
**Candidate trajectory (this loop):**
  - iter 1: 0.2630 (var=0.0072) (Δ vs real -0.0518)
  - iter 2: 0.2057 (var=0.0069) (Δ vs real -0.1091)
  - iter 3 (current): 0.2818 (var=0.0105) (Δ vs real -0.0330)
**Other theories' values on this metric (for reference):**
- pi_5_1: -0.0034 (var=0.0097)
- pi_6: 0.1752 (var=0.0110)
- pi_1: 0.4129 (var=0.0077)
- pi_2: -0.0132 (var=0.0118)
- pi_3: 0.0021 (var=0.0076)
- pi_4: -0.3642 (var=0.0070)
- pi_5: -0.0209 (var=0.0151)
- pi_7: 0.2316 (var=0.0094)
- pi_8: 0.2535 (var=0.0084)

### Experiment 12
**Design**
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 1, 0]  B=[0, 0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 0, 0]  B=[0, 1, 0, 0, 1, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 1, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 1, 1, 0]  B=[0, 1, 1, 0, 0, 1]
  A=[0, 1, 1, 0, 0, 1]  B=[1, 0, 0, 1, 1, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 1, 0]  B=[0, 1, 0, 1, 0, 0]
  A=[0, 1, 0, 1, 0, 0]  B=[1, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    """
    Primacy-slope metric on validity-matched cells (with X2-family
    orientation absorbed by a dummy).

    Logic: on every trial where the two options' winning-cue validity
    multisets are IDENTICAL (the 20 matched cells: D0,Z1,D1,W1,W2,D2,
    D2b,D3,D4,D5 + mirrors), the distrust kernel and the flat counting
    kernel cancel EXACTLY, so IVC predicts P(A)=0.500 parameter-free
    (the lapse preserves 0.5). PW-IVC predicts a systematic deviation
    graded by the primacy contrast C = w_prim . sign(A-B), with a
    steep convex reference gradient (eta=5).

    We also include the six X2-family cells (2 wins per side, unequal
    validity multisets). Under IVC all X2 cells share ONE probability
    that depends only on orientation (A-won-the-0.9 vs mirror), so a
    single +-1 orientation dummy Z absorbs IVC's entire mean structure
    there; the within-family position spread then loads on C.

    Metric = OLS coefficient of C in y ~ 1 + C + Z, with y = +1 (chose
    A) / -1 (chose B). Under IVC this coefficient is EXACTLY 0 in
    expectation for every admissible parameter. Under PW-IVC it is
    strictly positive (roughly 2*(1-eps)*beta*tau*rho scale), typically
    0.15-0.8.
    """
    import numpy as np
    import pandas as pd

    n = 6
    v = np.array([0.9, 0.6, 0.6, 0.6, 0.6, 0.9], dtype=float)

    # Reference primacy kernel (eta = 5): convex, front-loaded.
    pos = np.arange(n, dtype=float)
    prim = ((n - pos) / (n - 1.0)) ** 5.0
    w_prim = prim / prim.sum()

    # Reference inverted-validity kernel (gamma = 3, c = 0.1).
    # Only the SIGN of its dot product with s is used (orientation).
    err = 1.0 - v
    cent = np.maximum(err - 0.1 * float(err.min()), 0.0)
    u = cent ** 3.0
    u = u / u.sum()

    a = np.array([[float(t) for t in r] for r in data['option_a_ratings']], dtype=float)
    b = np.array([[float(t) for t in r] for r in data['option_b_ratings']], dtype=float)
    y = 1.0 - 2.0 * np.asarray(data['response'], dtype=float).ravel()  # +1 = A

    m = a.shape[0]
    if m == 0:
        return 0.0

    s = np.sign(a - b)
    aWin = a > b
    bWin = b > a

    C = np.zeros(m)
    Z = np.zeros(m)
    keep = np.zeros(m, dtype=bool)

    for i in range(m):
        ka = tuple(sorted(v[aWin[i]].tolist()))
        kb = tuple(sorted(v[bWin[i]].tolist()))
        nA = int(aWin[i].sum())
        nB = int(bWin[i].sum())
        if ka == kb and nA > 0:
            # Matched-validity cell: distrust+flat kernels cancel exactly.
            keep[i] = True
            C[i] = float(np.dot(w_prim, s[i]))
        elif nA == 2 and nB == 2 and ka != kb:
            # X2-family cell: orientation dummy absorbs IVC's constant
            # allegiance effect; position spread loads on C.
            keep[i] = True
            C[i] = float(np.dot(w_prim, s[i]))
            Z[i] = float(np.sign(np.dot(u, s[i])))

    if int(keep.sum()) < 12:
        return 0.0

    Ck = C[keep]
    Zk = Z[keep]
    yk = y[keep]

    X = np.column_stack([np.ones_like(Ck), Ck, Zk])
    try:
        coef, _, _, _ = np.linalg.lstsq(X, yk, rcond=None)
        return float(coef[1])
    except Exception:
        return 0.0
```

**Observed (real) value:** 0.5396 (var=0.0423)
**Candidate trajectory (this loop):**
  - iter 1: 0.5695 (var=0.0295) (Δ vs real +0.0299)
  - iter 2: 0.4036 (var=0.0413) (Δ vs real -0.1359)
  - iter 3 (current): 0.5896 (var=0.0270) (Δ vs real +0.0501)
**Other theories' values on this metric (for reference):**
- pi_6: 0.4027 (var=0.0731)
- pi_5_1: 0.0336 (var=0.0381)
- pi_1: 0.8316 (var=0.0733)
- pi_2: -0.0087 (var=0.0294)
- pi_3: -0.0421 (var=0.0393)
- pi_4: -0.6945 (var=0.0377)
- pi_5: 0.0254 (var=0.0512)
- pi_7: 0.4678 (var=0.0344)
- pi_8: 0.5770 (var=0.0378)

### Experiment 13
**Design**
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 1, 0, 0]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 0, 1, 0, 1]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 1, 0, 1, 0]
  A=[1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    # Trial specification keyed by (A ratings, B ratings) -> (family, aligned response).
    # Families (validities = [0.95, 0.5, 0.95, 0.5, 0.95, 0.5]; experts 1,3,5 are 95%, experts 2,4,6 are 50%):
    #   "H" : high-validity (95%) duels (trials 1-4); aligned = product winning the LATER expert (anti-primacy)
    #   "L" : low-validity (50%) duels (trials 7-10); aligned = product winning the EARLIER expert (primacy)
    #   "M" : distrust-neutralized position cells (trials 13-18); aligned = product winning expert 2
    #   "C" : count/validity-balanced coalition cells (trials 21-24); aligned = product winning experts {2,3}
    spec = {
        ((1, 0, 0, 0, 0, 0), (0, 0, 0, 0, 1, 0)): ("H", 1),
        ((0, 0, 0, 0, 1, 0), (1, 0, 0, 0, 0, 0)): ("H", 0),
        ((1, 0, 0, 0, 0, 0), (0, 0, 1, 0, 0, 0)): ("H", 1),
        ((0, 0, 1, 0, 0, 0), (1, 0, 0, 0, 0, 0)): ("H", 0),
        ((0, 1, 0, 0, 0, 0), (0, 0, 0, 0, 0, 1)): ("L", 0),
        ((0, 0, 0, 0, 0, 1), (0, 1, 0, 0, 0, 0)): ("L", 1),
        ((0, 1, 0, 0, 0, 0), (0, 0, 0, 1, 0, 0)): ("L", 0),
        ((0, 0, 0, 1, 0, 0), (0, 1, 0, 0, 0, 0)): ("L", 1),
        ((0, 1, 0, 0, 0, 0), (1, 0, 0, 0, 0, 1)): ("M", 0),
        ((1, 0, 0, 0, 0, 1), (0, 1, 0, 0, 0, 0)): ("M", 1),
        ((0, 1, 0, 0, 0, 0), (1, 0, 0, 1, 0, 0)): ("M", 0),
        ((1, 0, 0, 1, 0, 0), (0, 1, 0, 0, 0, 0)): ("M", 1),
        ((0, 1, 1, 0, 0, 0), (1, 0, 0, 0, 0, 1)): ("M", 0),
        ((1, 0, 0, 0, 0, 1), (0, 1, 1, 0, 0, 0)): ("M", 1),
        ((0, 1, 1, 0, 0, 0), (0, 0, 0, 1, 1, 0)): ("C", 0),
        ((0, 0, 0, 1, 1, 0), (0, 1, 1, 0, 0, 0)): ("C", 1),
        ((0, 1, 1, 0, 0, 0), (0, 0, 0, 0, 1, 1)): ("C", 0),
        ((0, 0, 0, 0, 1, 1), (0, 1, 1, 0, 0, 0)): ("C", 1),
    }

    hits = {"H": 0, "L": 0, "M": 0, "C": 0}
    tots = {"H": 0, "L": 0, "M": 0, "C": 0}

    a_cells = data["option_a_ratings"].tolist()
    b_cells = data["option_b_ratings"].tolist()
    r_vals = data["response"].tolist()

    for a_cell, b_cell, r in zip(a_cells, b_cells, r_vals):
        try:
            ka = tuple([int(x) for x in a_cell])
            kb = tuple([int(x) for x in b_cell])
            ri = int(r)
        except Exception:
            continue
        entry = spec.get((ka, kb))
        if entry is None:
            continue
        fam, al = entry
        tots[fam] += 1
        if ri == al:
            hits[fam] += 1

    def prop(fam):
        if tots[fam] == 0:
            return 0.5
        return hits[fam] / float(tots[fam])

    p_l = prop("L")  # P(earlier-expert product | low-validity duel)
    p_h = prop("H")  # P(later-expert product  | high-validity duel)
    p_m = prop("M")  # P(expert-2 product | distrust-neutralized cells)
    p_c = prop("C")  # P({2,3}-coalition product | balanced coalition cells)

    # (1) Validity-scaled position crossover: C = P(early|low duel) - P(early|high duel)
    #     = p_l + p_h - 1. Strictly positive under PGDT, strictly negative under PW-IVC
    #     at every corner of both parameter boxes (position effects are validity-
    #     AMPLIFIED under PGDT's multiplicative kernel, validity-INVARIANT under
    #     PW-IVC's additive kernel, where the position-1 expert always dominates).
    # (2) M-family: distrust terms cancel exactly in BOTH theories, leaving opposite-
    #     signed position architecture (PGDT: d>0 at every corner; PW-IVC: d<0 at every
    #     corner). Double-weighted because this is the only sign-DISJOINT family.
    # (3) Coalition cells: counting and distrust both cancel; only position varies.
    #     PGDT separates the coalition strongly (d in [0.08, 0.39]); PW-IVC caps at
    #     d <= 0.11. Double-weighted to use the 12 trials efficiently.
    crossover = p_l + p_h - 1.0
    m_term = 2.0 * (p_m - 0.5)
    c_term = 2.0 * (p_c - 0.5)

    return float(crossover + m_term + c_term)
```

**Observed (real) value:** 1.8356 (var=0.2112)
**Candidate trajectory (this loop):**
  - iter 1: 1.5822 (var=0.1254) (Δ vs real -0.2533)
  - iter 2: 1.3517 (var=0.1737) (Δ vs real -0.4839)
  - iter 3 (current): 1.6911 (var=0.1285) (Δ vs real -0.1444)
**Other theories' values on this metric (for reference):**
- pi_7: 1.1900 (var=0.2144)
- pi_6: -0.0794 (var=0.2347)
- pi_1: 0.0389 (var=0.0856)
- pi_2: -0.4917 (var=0.1577)
- pi_3: -0.2350 (var=0.2168)
- pi_4: -0.8106 (var=0.2217)
- pi_5: 0.0650 (var=0.2219)
- pi_5_1: 0.0894 (var=0.1646)
- pi_8: 1.7233 (var=0.1382)

### Experiment 14
**Design**
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 1, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 1, 1]
  A=[1, 0, 1, 0, 1, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 1, 0, 1, 1]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 1, 0, 0]
  A=[1, 0, 1, 1, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 1, 0]  B=[0, 1, 0, 1, 0, 0]
  A=[0, 1, 0, 1, 0, 0]  B=[1, 0, 0, 0, 1, 0]
  A=[1, 0, 0, 1, 0, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 1, 0, 1]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 1, 1]  B=[1, 0, 0, 1, 0, 0]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 1, 1, 0, 1, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np
    import pandas as pd

    # Critical "primacy-rescue" trial family: exactly one option carries the
    # position-1 trusted (0.95) expert, the opposing option carries only
    # early low-validity (0.50) experts. Six f1-side patterns (option that
    # holds the position-1 trusted expert) x two counterpart patterns.
    P = {
        (1, 0, 0, 0, 0, 1),  # {95%@1, 50%@6}          (L1 rung)
        (1, 0, 0, 0, 1, 1),  # {95%@1, 50%@5, 50%@6}   (L2 rung)
        (1, 0, 1, 0, 1, 1),  # {95%@1, 50%@3,5,6}     (L3 rung)
        (1, 0, 1, 0, 0, 0),  # {95%@1, 50%@3}          (L1e early helper)
        (1, 0, 1, 1, 0, 0),  # {95%@1, 50%@3, 95%@4}   (TB+ cell)
        (1, 0, 0, 0, 1, 0),  # {95%@1, 50%@5}          (FL cell)
    }
    Q = {
        (0, 1, 0, 0, 0, 0),  # {50%@2}
        (0, 1, 0, 1, 0, 0),  # {50%@2, 95%@4}
    }

    def to_key(x):
        return tuple(int(v) for v in x)

    hits = []
    a_col = data["option_a_ratings"]
    b_col = data["option_b_ratings"]
    r_col = data["response"]
    for a_raw, b_raw, r_raw in zip(a_col, b_col, r_col):
        a = to_key(a_raw)
        b = to_key(b_raw)
        r = int(r_raw)
        if a in P and b in Q:
            # trusted-early product is option A
            hits.append(1.0 if r == 0 else 0.0)
        elif b in P and a in Q:
            # trusted-early product is option B
            hits.append(1.0 if r == 1 else 0.0)

    if len(hits) == 0:
        return 0.5
    return float(np.mean(hits))
```

**Observed (real) value:** 0.1322 (var=0.0089)
**Candidate trajectory (this loop):**
  - iter 1: 0.3122 (var=0.0059) (Δ vs real +0.1800)
  - iter 2: 0.3500 (var=0.0052) (Δ vs real +0.2178)
  - iter 3 (current): 0.2889 (var=0.0068) (Δ vs real +0.1567)
**Other theories' values on this metric (for reference):**
- pi_6: 0.6911 (var=0.0080)
- pi_7: 0.4311 (var=0.0074)
- pi_1: 0.8344 (var=0.0128)
- pi_2: 0.7878 (var=0.0063)
- pi_3: 0.6217 (var=0.0047)
- pi_4: 0.6733 (var=0.0080)
- pi_5: 0.5822 (var=0.0076)
- pi_5_1: 0.5911 (var=0.0082)
- pi_8: 0.3094 (var=0.0064)

### Experiment 15
**Design**
  A=[1, 1, 1, 1, 1, 1, 0]  B=[0, 1, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 0, 1]  B=[0, 1, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0, 1]
  A=[1, 1, 1, 1, 1, 1, 0]  B=[1, 0, 1, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 0, 1]  B=[1, 0, 1, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0, 1]
  A=[1, 0, 1, 1, 1, 1, 1]  B=[0, 1, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1, 1]  B=[1, 0, 1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 0, 0]  B=[0, 0, 1, 1, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 1, 0, 0]  B=[0, 1, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 0]  B=[0, 0, 1, 1, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 0, 1, 1, 1]  B=[1, 1, 0, 1, 0, 1, 1]
  A=[1, 1, 0, 1, 0, 1, 1]  B=[1, 1, 1, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 1, 1, 1]  B=[1, 1, 0, 1, 1, 1, 1]
  A=[1, 1, 0, 1, 1, 1, 1]  B=[1, 1, 1, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 0, 0, 0]  B=[1, 1, 1, 0, 1, 1, 1]
  A=[1, 1, 1, 0, 1, 1, 1]  B=[0, 0, 0, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 1, 1, 1]  B=[0, 1, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1, 1]  B=[1, 1, 1, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 0, 1, 1]  B=[1, 1, 0, 1, 1, 1, 1]
  A=[1, 1, 0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0, 1, 1]
  A=[1, 1, 1, 1, 0, 1, 0]  B=[0, 1, 0, 1, 1, 1, 1]
  A=[0, 1, 0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0, 1, 0]
  A=[1, 1, 1, 1, 1, 0, 0]  B=[0, 1, 1, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    """Gate-vs-ramp discrimination score (theory-informed linear contrast).

    Each of the 32 design cells gets a fixed coefficient c equal (in sign and
    rough magnitude) to the predicted difference P(A | PGDT) - P(A | PRDT)
    for that cell.  The score is the mean of c * (+1 if chose A, -1 if chose B)
    over the session, x100.  Under PGDT (position-independent trusted bracket
    ordered by the primacy gate) the score is strongly positive; under PRDT
    (t0 = 0 trust ramp that kills early trusted experts) it is much smaller.
    Mirrored cells carry opposite coefficients, so side/position bias cancels.
    """
    if data is None or len(data) == 0:
        return 0.0
    for col in ("option_a_ratings", "option_b_ratings", "response"):
        if col not in data.columns:
            return 0.0

    # (A_ratings, B_ratings) -> contrast coefficient
    _TRIALS = [
        # --- trusted-position axis (sign-robust at every parameter corner) ---
        ((1, 1, 1, 1, 1, 1, 0), (0, 1, 1, 1, 1, 1, 1),  0.050),  # D17
        ((0, 1, 1, 1, 1, 1, 1), (1, 1, 1, 1, 1, 1, 0), -0.050),
        ((1, 1, 1, 1, 1, 0, 1), (0, 1, 1, 1, 1, 1, 1),  0.045),  # D16
        ((0, 1, 1, 1, 1, 1, 1), (1, 1, 1, 1, 1, 0, 1), -0.045),
        ((1, 1, 1, 1, 1, 1, 0), (1, 0, 1, 1, 1, 1, 1),  0.022),  # D27-type
        ((1, 0, 1, 1, 1, 1, 1), (1, 1, 1, 1, 1, 1, 0), -0.022),
        ((1, 1, 1, 1, 1, 0, 1), (1, 0, 1, 1, 1, 1, 1),  0.020),  # D26-type
        ((1, 0, 1, 1, 1, 1, 1), (1, 1, 1, 1, 1, 0, 1), -0.020),
        ((1, 0, 1, 1, 1, 1, 1), (0, 1, 1, 1, 1, 1, 1),  0.012),  # pos1 vs pos0
        ((0, 1, 1, 1, 1, 1, 1), (1, 0, 1, 1, 1, 1, 1), -0.012),
        ((1, 1, 1, 1, 1, 0, 0), (0, 0, 1, 1, 1, 1, 1),  0.060),  # BLK
        ((0, 0, 1, 1, 1, 1, 1), (1, 1, 1, 1, 1, 0, 0), -0.060),
        ((1, 1, 1, 1, 1, 0, 0), (0, 1, 1, 1, 1, 1, 1),  0.040),  # BLKa
        ((0, 1, 1, 1, 1, 1, 1), (1, 1, 1, 1, 1, 0, 0), -0.040),
        ((1, 1, 1, 1, 1, 1, 0), (0, 0, 1, 1, 1, 1, 1),  0.070),  # T21
        ((0, 0, 1, 1, 1, 1, 1), (1, 1, 1, 1, 1, 1, 0), -0.070),
        # --- kernel-steepness / anti-validity axis ---
        ((1, 1, 1, 0, 1, 1, 1), (1, 1, 0, 1, 0, 1, 1), -0.080),  # ML1
        ((1, 1, 0, 1, 0, 1, 1), (1, 1, 1, 0, 1, 1, 1),  0.080),
        ((1, 1, 1, 0, 1, 1, 1), (1, 1, 0, 1, 1, 1, 1), -0.050),  # ML2
        ((1, 1, 0, 1, 1, 1, 1), (1, 1, 1, 0, 1, 1, 1),  0.050),
        ((0, 0, 0, 1, 0, 0, 0), (1, 1, 1, 0, 1, 1, 1),  0.050),  # ANCH
        ((1, 1, 1, 0, 1, 1, 1), (0, 0, 0, 1, 0, 0, 0), -0.050),
        ((1, 1, 1, 0, 1, 1, 1), (0, 1, 1, 1, 1, 1, 1), -0.015),  # TL
        ((0, 1, 1, 1, 1, 1, 1), (1, 1, 1, 0, 1, 1, 1),  0.015),
        ((1, 1, 1, 1, 0, 1, 1), (1, 1, 0, 1, 1, 1, 1),  0.012),  # MM
        ((1, 1, 0, 1, 1, 1, 1), (1, 1, 1, 1, 0, 1, 1), -0.012),
        ((1, 1, 1, 1, 0, 1, 0), (0, 1, 0, 1, 1, 1, 1),  0.045),  # mixed
        ((0, 1, 0, 1, 1, 1, 1), (1, 1, 1, 1, 0, 1, 0), -0.045),
        ((1, 1, 1, 1, 1, 0, 0), (0, 1, 1, 0, 1, 1, 1),  0.005),  # MX
        ((0, 1, 1, 0, 1, 1, 1), (1, 1, 1, 1, 1, 0, 0), -0.005),
        # TOT anchors: no theory contrast (lapse-only difference) -> weight 0
        ((1, 1, 1, 1, 1, 1, 1), (0, 0, 0, 0, 0, 0, 0),  0.000),
        ((0, 0, 0, 0, 0, 0, 0), (1, 1, 1, 1, 1, 1, 1),  0.000),
    ]
    W = {(a, b): c for a, b, c in _TRIALS}

    def _key(cell):
        # robustly convert a list/tuple/ndarray/string of binary ratings
        # into a hashable tuple of ints
        if isinstance(cell, str):
            s = cell.replace("[", " ").replace("]", " ").replace(",", " ")
            try:
                return tuple(int(round(float(t))) for t in s.split())
            except ValueError:
                return None
        try:
            arr = np.asarray(cell, dtype=float).ravel()
            return tuple(int(round(float(v))) for v in arr)
        except Exception:
            return None

    total = 0.0
    n = 0
    for a, b, r in zip(data["option_a_ratings"].tolist(),
                       data["option_b_ratings"].tolist(),
                       data["response"].tolist()):
        ka = _key(a)
        kb = _key(b)
        if ka is None or kb is None:
            continue
        c = W.get((ka, kb), 0.0)
        try:
            rv = int(round(float(r)))
        except (TypeError, ValueError):
            continue
        y = 1.0 if rv == 0 else -1.0  # +1 = chose A, -1 = chose B
        total += c * y
        n += 1

    if n == 0:
        return 0.0
    return 100.0 * total / n
```

**Observed (real) value:** 1.0358 (var=0.1926)
**Candidate trajectory (this loop):**
  - iter 1: 0.9752 (var=0.2106) (Δ vs real -0.0607)
  - iter 2: 0.9105 (var=0.1864) (Δ vs real -0.1253)
  - iter 3 (current): 1.0504 (var=0.1498) (Δ vs real +0.0145)
**Other theories' values on this metric (for reference):**
- pi_7: 1.2013 (var=0.2191)
- pi_8: 0.7713 (var=0.1699)
- pi_1: 0.7452 (var=0.1677)
- pi_2: -0.4130 (var=0.1912)
- pi_3: -0.0560 (var=0.2308)
- pi_4: -1.3777 (var=0.2014)
- pi_5: 0.7034 (var=0.1475)
- pi_5_1: 0.7465 (var=0.2677)
- pi_6: 1.6376 (var=0.1716)

### Experiment 16
**Design**
  A=[0, 0, 0, 0, 0, 1, 1, 1]  B=[0, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 1, 1, 1]  B=[0, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 1, 1, 1]  B=[0, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1, 1, 0]
  A=[1, 1, 1, 0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1]
  A=[1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 0, 1, 1, 1]  B=[0, 0, 0, 0, 1, 0, 0, 0]
  A=[1, 1, 1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1, 1, 1]
  A=[0, 0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 1, 1, 0]  B=[0, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 1, 1, 0]  B=[0, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0, 0, 0]  B=[1, 1, 1, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0, 0, 0]  B=[1, 1, 1, 0, 0, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0, 0, 0]  B=[1, 1, 1, 1, 0, 1, 1, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1, 1, 1]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    # Two-stage, layout-adaptive theory discriminant.
    # Stage 1 infers which validity layout generated the data (the design
    # header lists [0.99, 0.99, 0.99, 0.75, 0.75, 0.75, 0.75, 0.75] while
    # the rationale/trial list is built around a 0.55 expert at position
    # 5). The inference uses only the clean two-cue duels involving
    # position 5: under the 0.55 layout BOTH theories prefer the
    # position-5-endorsed product with P ~ 0.7-0.9; under the all-0.75
    # layout that probability is ~ 0.5. This is a theory-agnostic,
    # mirror-balanced statistic, so it is safe to branch on.
    # Stage 2 computes a gap-weighted choice discriminant: for every unique
    # (A, B) rating pattern it evaluates the box-averaged predicted P(A)
    # of PRDT (distrust inversion with gamma in [1.6, 2.2], floored primacy
    # gate, position-growing trust ramp with t0 pinned at 0) and of PGDT
    # (gamma in [2.8, 3.5], position-independent flat share (1-tau)/8),
    # using each theory's own mechanics verbatim, and weights the observed
    # choose-A indicator by the signed predicted gap. Mirrored cells
    # automatically reinforce. The score is linear in the trial outcomes,
    # so the pooled value equals the mean of the per-subject values and
    # the metric works on single-subject slices.

    def _vec(x):
        try:
            arr = np.asarray(list(x), dtype=float)
            if arr.size == 0:
                raise ValueError("empty cell")
            return arr
        except Exception:
            s = str(x).strip()
            for ch in "[](),":
                s = s.replace(ch, " ")
            return np.asarray([float(t) for t in s.split() if t != ""], dtype=float)

    if data is None or len(data) == 0:
        return 0.0

    df = data.reset_index(drop=True)
    a_list = [_vec(x) for x in df["option_a_ratings"].tolist()]
    b_list = [_vec(x) for x in df["option_b_ratings"].tolist()]
    resp = df["response"].to_numpy(dtype=float)
    n = int(a_list[0].size)
    chose_a = 1.0 - resp

    if n != 8:
        return float(np.mean(chose_a))

    # ---------- Stage 1: layout inference ----------
    y5 = []
    for av, bv, ca in zip(a_list, b_list, chose_a):
        s = np.sign(av - bv)
        nz = np.where(np.abs(s) > 0.5)[0]
        if len(nz) == 2 and 4 in nz:
            endorsed_a = bool(s[4] > 0)
            picked_a = bool(ca > 0.5)
            y5.append(1.0 if (endorsed_a == picked_a) else 0.0)
    p5 = float(np.mean(y5)) if len(y5) > 0 else 0.5

    if p5 > 0.60:
        v = np.array([0.99, 0.99, 0.99, 0.75, 0.55, 0.75, 0.75, 0.75], dtype=float)
    else:
        v = np.array([0.99, 0.99, 0.99, 0.75, 0.75, 0.75, 0.75, 0.75], dtype=float)

    # ---------- Stage 2: reference theory predictions ----------
    def _prdt_w(tau, eta, delta, gamma, c, t1, kappa):
        err = 1.0 - v
        centered = np.maximum(err - c * float(err.min()), 0.0)
        inv = np.power(centered, gamma)
        Z = float(inv.sum())
        if Z > 1e-12:
            w_inv = inv / Z
        else:
            w_inv = np.full(8, 0.125)
        pos = np.arange(8, dtype=float)
        t = t1 * np.power(pos / 7.0, kappa)  # t0 pinned at exactly 0
        g = delta + (1.0 - delta) * np.power((8.0 - pos) / 7.0, eta)
        bracket = t * (1.0 - tau) / 8.0 + tau * w_inv
        raw = g * bracket
        Zt = float(raw.sum())
        if Zt > 1e-12:
            return raw / Zt
        return np.full(8, 0.125)

    def _pgdt_w(tau, eta, delta, gamma, c):
        err = 1.0 - v
        centered = np.maximum(err - c * float(err.min()), 0.0)
        inv = np.power(centered, gamma)
        Z = float(inv.sum())
        if Z > 1e-12:
            w_inv = inv / Z
        else:
            w_inv = np.full(8, 0.125)
        pos = np.arange(8, dtype=float)
        g = delta + (1.0 - delta) * np.power((8.0 - pos) / 7.0, eta)
        bracket = (1.0 - tau) / 8.0 + tau * w_inv
        raw = g * bracket
        Zt = float(raw.sum())
        if Zt > 1e-12:
            return raw / Zt
        return np.full(8, 0.125)

    def _pa(w, s, beta, eps):
        d = float(np.dot(w, s))
        p = 0.5 * (1.0 + np.tanh(0.5 * beta * d))
        return (1.0 - eps) * p + 0.5 * eps

    prdt_base = dict(tau=0.915, eta=5.5, delta=0.275, gamma=1.9, c=0.15,
                     t1=0.925, kappa=2.25, beta=4.75, eps=0.11)
    prdt_draws = [dict(prdt_base)]
    for gm in (1.6, 2.2):
        for ta in (0.90, 0.93):
            for be in (4.0, 5.5):
                for t1v in (0.85, 1.0):
                    dr = dict(prdt_base)
                    dr["gamma"] = gm
                    dr["tau"] = ta
                    dr["beta"] = be
                    dr["t1"] = t1v
                    prdt_draws.append(dr)
    prdt_edges = {"eta": (5.0, 6.0), "delta": (0.25, 0.30),
                  "kappa": (1.5, 3.0), "c": (0.0, 0.3), "eps": (0.09, 0.13)}
    for key in prdt_edges:
        for val in prdt_edges[key]:
            dr = dict(prdt_base)
            dr[key] = val
            prdt_draws.append(dr)

    pgdt_base = dict(tau=0.87, eta=5.0, delta=0.325, gamma=3.15, c=0.175,
                     beta=4.25, eps=0.105)
    pgdt_draws = [dict(pgdt_base)]
    for gm in (2.8, 3.5):
        for ta in (0.82, 0.92):
            for dl in (0.20, 0.45):
                for be in (2.5, 6.0):
                    dr = dict(pgdt_base)
                    dr["gamma"] = gm
                    dr["tau"] = ta
                    dr["delta"] = dl
                    dr["beta"] = be
                    pgdt_draws.append(dr)
    pgdt_edges = {"eta": (4.0, 6.0), "c": (0.10, 0.25), "eps": (0.06, 0.15)}
    for key in pgdt_edges:
        for val in pgdt_edges[key]:
            dr = dict(pgdt_base)
            dr[key] = val
            pgdt_draws.append(dr)

    # ---------- Stage 3: gap-weighted choice discriminant ----------
    info = {}
    for av, bv, ca in zip(a_list, b_list, chose_a):
        key = (tuple(int(round(x)) for x in av), tuple(int(round(x)) for x in bv))
        if key not in info:
            s = np.sign(av - bv)
            pp = []
            for dr in prdt_draws:
                w = _prdt_w(dr["tau"], dr["eta"], dr["delta"], dr["gamma"],
                            dr["c"], dr["t1"], dr["kappa"])
                pp.append(_pa(w, s, dr["beta"], dr["eps"]))
            pg = []
            for dr in pgdt_draws:
                w = _pgdt_w(dr["tau"], dr["eta"], dr["delta"], dr["gamma"], dr["c"])
                pg.append(_pa(w, s, dr["beta"], dr["eps"]))
            info[key] = [0, 0.0, float(np.mean(pp)) - float(np.mean(pg))]
        info[key][0] += 1
        info[key][1] += float(ca)

    num = 0.0
    den = 0.0
    for key in info:
        cnt, na, gap = info[key]
        if abs(gap) < 1e-9:
            continue
        y = na / float(cnt)
        num += gap * (2.0 * y - 1.0) * cnt
        den += abs(gap) * cnt
    if den <= 1e-12:
        return 0.0
    return float(num / den)
```

**Observed (real) value:** 0.3217 (var=0.0143)
**Candidate trajectory (this loop):**
  - iter 1: 0.3211 (var=0.0244) (Δ vs real -0.0005)
  - iter 2: 0.3501 (var=0.0131) (Δ vs real +0.0284)
  - iter 3 (current): 0.3459 (var=0.0187) (Δ vs real +0.0242)
**Other theories' values on this metric (for reference):**
- pi_8: 0.4993 (var=0.0158)
- pi_7: 0.2921 (var=0.0253)
- pi_1: -0.3540 (var=0.0203)
- pi_2: 0.0555 (var=0.0223)
- pi_3: 0.0175 (var=0.0135)
- pi_4: 0.2437 (var=0.0175)
- pi_5: 0.2891 (var=0.0130)
- pi_5_1: 0.3482 (var=0.0169)
- pi_6: 0.1779 (var=0.0330)

## YOUR PRIOR CRITIQUES (for this propose-loop)
Each block is one of YOUR previous critique iterations: the verdict you returned, the interpretation and rationale you wrote, and an **Outcome of your advice** line that says whether the candidate the proposer produced AFTER following your advice was ACCEPTED (your advice helped — its loss strictly beat the running-best) or REJECTED (your advice didn't help — the gate discarded the candidate). Use this self-history to (a) reinforce advice that was ACCEPTED, (b) avoid repeating advice that was REJECTED, and (c) detect your own oscillation across iterations.

### Iteration 1
Verdict: regenerate
Interpretation: PBDT is a genuine improvement over both parents and was rightly accepted by the gate (loss 0.1120). It delivers on several of the arbiter's targeted experiments: Exp 16 is essentially perfect (0.3211 vs 0.3217, where pi_7 undershot at 0.292 and pi_8 overshot at 0.499), Exp 13 jumps from pi_7's 1.19 to 1.58 (real 1.84), Exp 12 improves to 0.5695 (real 0.5396), Exp 15 lands at 0.9752 (real 1.0358, closer than pi_7's 1.2013), and Exp 1 improves to 0.1897 (real 0.2080) versus pi_7's 0.1637 / pi_8's 0.1093. The bridged gamma and nonzero trust floor clearly worked as intended there. However, four systematic residuals remain, and they are coherent enough to guide a tuning pass rather than a redesign: (1) Exp 2 tally-vs-TTB contrast is 0.3088 vs real 0.1583 — essentially unchanged from pi_7's 0.2996, so the joint noise recalibration (beta 3-5, eps 0.10-0.16) did not bite; the fitted response function is still too deterministic on conflict trials (also visible in Exp 4: 0.8925 vs 0.8433, and Exp 7: 0.8522 vs 0.7878). (2) Exp 3's anti-validity partial coefficient is only -0.2651 vs real -0.5756, with between-subject variance more than double the real data (0.042 vs 0.019) — worse than either parent (pi_7 -0.438, pi_8 -0.484). Diagnosis: in Exp 3 validities are strictly decreasing in position, so the steep primacy gate boosts exactly the high-validity (low distrust) cues and cancels the anti-validity gradient; the gate is too steep / the distrust channel too weak in this confounded layout. (3) Exp 14 trusted-early following is 0.3122 vs real 0.1322 — better than pi_7's 0.431 but still 2.4x the observed rate; the position-1 95% expert retains too much weight via the t0 floor times the flat share. (4) Exp 8 final-expert following is 0.2700 vs real 0.3957 — the late 0.90-validity expert gets zero distrust weight after centering (its error rate IS the minimum, so centered=0) and only the tiny t*(1-tau)/n channel, so it is still over-crushed. All four residuals point in compatible in-family directions.
Rationale: The candidate was ACCEPTED and becomes the new base, so this regenerate verdict means 'keep tuning this base', not 'discard it'. The residuals are coherent and fixable with parameter re-balancing inside the prescribed PBDT family, no architectural change: (a) SHARPEN THE TRUST-RAMP CONTRAST — lower t0 to [0.25, 0.35], raise t1 to [0.95, 1.00], and lower kappa to [1.0, 1.5]. This simultaneously attacks Exp 14 (less early-trusted weight → following drops from 0.31 toward 0.13) and Exp 8 (late trusted experts recover more of the flat share → FEDI rises from 0.27 toward 0.40); the ramp's position dependence is exactly the knob that lets both move at once. (b) STRENGTHEN THE DISTRUST CHANNEL where position and validity are confounded: gamma toward the upper end [2.6, 2.9] and tau toward [0.91, 0.93], with eta at the LOWER end [5.5, 6.0] and delta at the upper end [0.25, 0.30] so late low-validity cues are not crushed by the gate — this targets Exp 3 (coefficient from -0.265 toward -0.576, and reduce the excessive var=0.042) and Exp 13 (1.58 toward 1.84) without giving up Exp 16, where the current fit is nearly exact and should be monitored as a constraint. (c) REDUCE RESPONSE DETERMINISM: beta to [3.0, 3.8] and epsilon to [0.13, 0.16]; the previous noise recalibration failed because the fitted beta evidently sat high — the Exp 2 contrast (0.309 vs 0.158), Exp 4 anchors (0.893 vs 0.843) and Exp 7 (0.852 vs 0.788) all shrink toward the data with a flatter logistic, and the lapse mechanically attenuates every contrast metric. Watch Exp 1 (currently good at 0.190 vs 0.208) and Exp 12 (0.570 vs 0.540) for over-correction: if lowering beta pushes those past the data, split the difference on beta (~3.5-4.0) and lean more on epsilon. These three moves are mutually reinforcing except for a mild tension between tau-up (helps Exps 3/13/14) and the flat share that Exp 8 needs — resolve it via the t1/kappa end of the ramp rather than lowering tau.

**Outcome of your advice:** iter 1 candidate loss=0.1120 -> iter 2 candidate loss=0.1011 -> the gate marked it ACCEPTED.

### Iteration 2 (most recent)
Verdict: regenerate
Interpretation: The iter-2 tuning was accepted by the gate (loss 0.1120 -> 0.1011) and my iter-1 advice was partially vindicated: the distrust-channel strengthening delivered a major win on Exp 3 (-0.265 -> -0.479 vs real -0.576, with variance now 0.0138 vs real 0.0186 — better than either parent), and Exps 5, 9, and 10 are now essentially exact (0.225 vs 0.231, 0.332 vs 0.341, -0.187 vs -0.173). Exp 16 remains near-perfect (0.350 vs 0.322) and Exps 4/7 moved toward the data (0.879 vs 0.843, 0.820 vs 0.788). However, the iteration also produced three clear regressions that diagnose precisely which sub-moves were wrong. (1) Exp 14 trusted-early following ROSE from 0.312 to 0.350 vs real 0.132 — the opposite of the intended direction. Mechanism: my directive (b) bundled two moves, and the eta-down/delta-up gate flattening un-crushed the late 50%-validity helper cues on the P-side patterns (positions 3,5,6) relative to Q-side's single early 50%@2, so the trusted-early product gained net weight even as t0 fell. The gamma/tau strengthening was the efficacious half of that directive (Exp 3's win); the gate flattening was the counterproductive half. (2) Exp 13 dropped from 1.58 to 1.35 vs real 1.84 — the same gate flattening hurt the M/C position families, and it is now WORSE than pi_8's 1.72. (3) The noise increase over-attenuated every slope/contrast metric that was already at or below the real value: Exp 12 fell from 0.570 to 0.404 (real 0.540), Exp 11 from 0.263 to 0.206 (real 0.315), Exp 1 from 0.190 to 0.156 (real 0.208), Exp 15 from 0.975 to 0.911 (real 1.036). The lapse/beta levers are global attenuators, and they were pushed past the point where the experiments that needed flattening (4, 7) stopped gaining and the ones that didn't (1, 11, 12, 13, 15) started losing. Meanwhile Exp 2 barely responded (0.309 -> 0.299 vs real 0.158): its discrepancy is structural (weight-based, not noise-based) and every distrust-family theory sits at ~0.30 there (pi_7: 0.300, pi_8: 0.403), so it should be treated as a monitored constraint rather than a tuning target. Exp 8 improved only modestly (0.270 -> 0.294 vs real 0.396); the late 0.90-validity expert's distrust weight is near-zero after centering and the trust channel is capped by (1-tau)/n.
Rationale: Keep the accepted iter-2 base and make one more targeted in-family pass with three directives, explicitly un-bundling my previous coupled advice. (A) UN-BUNDLE DIRECTIVE (b): REVERT THE GATE FLATTENING while KEEPING the distrust strengthening. Set eta back to the steep end, [6.5, 8.0], and delta back down to [0.15, 0.25], but PRESERVE gamma [2.6, 2.9] and tau [0.91, 0.93] exactly as in iter-2. The Exp 3 win came from the distrust kernel, not the gate — in Exp 3's validity-position-confounded layout the steep gamma/tau channel carries the anti-validity gradient on its own — while the steep gate is the ONLY lever that structurally separates Exp 14 (crush the late 50% helpers on the trusted-early side, pushing 0.350 back toward 0.132) from Exp 3. A steep gate plus strong distrust should also partially recover Exp 13 (iter-1 with a steep gate scored 1.58; pi_8's t0=0 architecture shows the H-family anti-primacy ceiling is reachable). (B) PARTIALLY ROLL BACK THE NOISE: beta to [3.6, 4.4] and epsilon to [0.11, 0.14] — between the iter-1 and iter-2 settings, not a full return to [3.0, 5.0]/[0.10, 0.16]. This should lift the over-attenuated slope metrics (Exp 12: 0.404 -> toward 0.54; Exp 11: 0.206 -> toward 0.31; Exp 1: 0.156 -> toward 0.21; Exp 13 and 15 likewise) at a cost of only ~+0.01-0.02 on Exps 4/7, which currently have margin (0.879 vs 0.843, 0.820 vs 0.788). Do NOT chase Exp 2 with further noise — it is noise-insensitive and structural in this family; hold it as a constraint. (C) FOR EXP 8, widen only the ramp's convexity downward as a minor in-family adjustment: kappa to [0.8, 1.5] (slightly below the arbiter's floor of 1.0, a concave-leaning ramp) so the late trusted expert recovers more of the flat share without touching t0, tau, or the gate — this is the one remaining lever for FEDI (0.294 -> toward 0.396) that does not conflict with (A) or (B). Watch-points: Exp 16 (currently 0.350 vs 0.322, still the family's best fit — the steep gate should not push it past ~0.05 error) and Exp 3 (confirm the reverted gate does not drag the coefficient back above -0.40; if it does, recover it via the upper end of gamma, 2.8-2.9, rather than re-flattening the gate). No architectural change: the multiplicative gate-times-bracket kernel, additive integration, and logistic-lapse choice rule are preserved verbatim.

**Outcome of your advice:** iter 2 candidate loss=0.1011 -> CURRENT candidate loss=0.0955 -> the gate marked it ACCEPTED.

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of the model simulation results on existing experiments and how they do or do not support the proposed model/theory.
- verdict: Either 'regenerate' (regenerate a new model/theory) or 'continue' (keep the current model/theory).
- rationale: If verdict='regenerate', why the current predict / policy / parameter-ranges should be revised. If verdict='continue', a sketch of why the current theory should be kept.


## Response

```json
{
  "interpretation": "Iter-3 was accepted (loss 0.1011 -> 0.0955) and my iter-2 un-bundling directives worked essentially as designed. The gate re-steepening (A) delivered: Exp 14's trusted-early following dropped from 0.350 back to 0.289 (real 0.132), Exp 13 recovered from 1.35 to 1.69 (real 1.84), and Exp 16 stayed within tolerance (0.346 vs 0.322). The partial noise roll-back (B) lifted every over-attenuated slope metric without breaking the anchors: Exp 12 0.404 -> 0.590 (real 0.540), Exp 11 0.206 -> 0.282 (real 0.315), Exp 15 0.911 -> 1.050 (real 1.036, now essentially exact and best-in-pool), Exp 1 0.156 -> 0.160. The distrust channel preserved the iter-2 Exp 3 win reasonably (-0.446 vs real -0.576, with variance 0.017 matching the real 0.019 \u2014 better calibrated than either parent). Exps 5 and 9 remain close, Exp 4 acceptable (+0.043). The remaining residuals are now well-characterized and, importantly, STRUCTURAL rather than tunable: (i) Exp 2 (+0.160) \u2014 every distrust-family theory sits at ~0.30 (pi_7: 0.300, pi_8: 0.403); it is a weight-architecture signature, not a noise miscalibration, as two iterations of beta/epsilon moves confirmed. (ii) Exp 8 (-0.115) and Exp 14 (+0.157) are in DIRECT tension inside the prescribed multiplicative kernel: the late 0.90-validity expert of Exp 8 and the late 50%-validity helpers of Exp 14 are both scaled by the same gate g_j, so any lever that lifts one (higher delta, higher (1-tau), earlier kappa recovery) pushes the other away \u2014 the kappa widening to [0.8, 1.5] in fact did not help Exp 8 (0.294 -> 0.280) because the steep gate, not the ramp, caps the late expert's weight. Resolving this would require gating only the distrust channel, which deviates from the arbiter's explicitly prescribed multiplicative form w_j \u221d g_j*[t_j*(1-tau)/n + tau*inv_j] and is therefore out of scope. (iii) Exp 3's small regression (-0.479 -> -0.446) was the predicted cost of re-steepening and is within the noise of the metric's between-subject variance. Pushing gamma to the top of [2.6, 2.9] might recover Exp 3/14 slightly but would degrade Exps 5, 7 and 10, which currently sit at or near the data \u2014 a zero-sum shuffle. The loss trajectory is flattening (0.1120 -> 0.1011 -> 0.0955) and the candidate is the best-fitting theory in the entire pool on aggregate, best-in-pool outright on Exps 15, 16, 12, 5, and competitive everywhere except the structurally-locked Exp 2.",
  "verdict": "continue",
  "rationale": "Ship it. The candidate is the running-best at loss 0.0955, monotonically improved across three accepted iterations, and captures the experiment-invariant signature the arbiter targeted: bridged distrust inversion (Exp 3 anti-validity with matching variance), steep floored primacy gate over distrusted cues (Exps 13, 14, 16), and a floored trust ramp (Exps 1, 15). The three remaining material residuals are not addressable by further in-family tuning: Exp 2 is locked at ~0.30 by the weight architecture shared by the whole distrust family; Exp 8 vs Exp 14 form a genuine identifiability tension inside the prescribed multiplicative gate-times-bracket kernel (both late-cue families share g_j), and my own iter-1 -> iter-2 history on the gate (flatten, then re-steepen) shows that further pushes in either direction trade accepted experiments one-for-one \u2014 the classic oscillation signal to stop. Marginal remaining gains (gamma top-end for Exp 3/14) are offset by losses on Exps 5/7/10, which are currently at or near the real values. The theory is experiment-invariant in the sense that matters: its parameter story (gamma ~2.6-2.9, tau ~0.91-0.93, steep eta with low delta, floored trust ramp, moderate noise) is a single coherent configuration that no longer requires per-experiment contortions. Continuing to tune would risk regressing the accepted base for negligible aggregate gain."
}
```

## Usage

```json
{
  "input_tokens": 47134,
  "output_tokens": 5057,
  "reasoning_tokens": 3968,
  "provider": "Sail Research"
}
```
