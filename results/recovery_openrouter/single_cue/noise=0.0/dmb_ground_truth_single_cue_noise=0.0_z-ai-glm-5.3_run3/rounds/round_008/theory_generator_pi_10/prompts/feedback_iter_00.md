# feedback_iter_00

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
- THEORY 2 = `pi_9`
- The recommendation below acts on THEORY 1 (= `pi_7`).

Propose 'RECIPROCAL-TRUST DISTRUST TALLYING (RTDT)' as the replacement for pi_7. Architecture: (1) Keep the distrust-inversion kernel verbatim (inv_j = ((1-v_j) - c*min(1-v))^gamma / Z) but steepen it: gamma in [3.0, 4.2], tau in [0.92, 0.96]. This directly repairs the under-predicted anti-validity slope (Exp5 observed -0.576 vs -0.418) and the under-shot position-crossover composite (Exp15), and the stronger kernel dominance automatically weakens count/tally allegiance toward Exp4's observed 0.158. (2) Replace the trust ramp with a RECIPROCAL one: t_j = t0 * (t1/t0)^(j/(n-1))^kappa with t0 in [0.00, 0.12] — an even lower early-trust floor than PBDT's [0.25, 0.35], fixing Exp16's severe over-prediction of primacy-rescue (observed 0.132 vs PBDT 0.264) — and t1 in [1.0, 1.6] with kappa in [0.6, 1.2], so LATE high-validity experts are not merely restored but AMPLIFIED above the flat share. This late-trusted amplification is the key novel lever: it fixes Exp10 (final 0.90-validity expert followed at 0.396 while both current theories predict ~0.28) without raising the early floor. (3) Keep the floored convex primacy gate but at the moderate range (eta [4.5, 6.5], delta [0.15, 0.30]) — the steep-gate/low-floor corner that PBDT verified. (4) Attenuate the choice rule: beta in [2.8, 4.0], epsilon in [0.12, 0.18], since both current theories systematically over-commit on allegiance metrics (Exps 4, 6, 9). (5) Evidence integration stays additive over discriminating cues, d = sum_j w_j*sign(A_j - B_j), logistic in beta*d with uniform lapse. The theory differs from PBDT in exactly three quantifiable respects (near-zero t0, super-unity t1, steeper gamma) each targeted at a documented residual, and differs from PGDT in retaining the position-dependent trusted channel that the log-Bayes-factor evidence decisively supports. It should be falsifiable on: Exp16 (predict rescue rate near 0.10-0.20), Exp10 (FEDI near 0.38-0.45), Exp4 (allegiance near 0.15-0.22), while matching PBDT on Exps 1, 2, 15, 17 where PBDT already succeeds.


## CANDIDATE THEORY
RECIPROCAL-TRUST DISTRUST TALLYING (RTDT). Subjects scan the expert ratings in presentation order through a steep floored convex primacy gate g_j = delta + (1-delta)*((n-j)/(n-1))^eta, so the first one or two experts carry the dominant share of attention while late experts retain only a floor residue. Stated validities are distrust-inverted (treated as error rates) via a STEEP kernel inv_j = ((1-v_j) - c*min_k(1-v_k))^gamma / Z with gamma in [3.0, 4.2] and a high distrust share tau in [0.92, 0.96], so the anti-validity gradient in validity-position-confounded layouts is carried almost entirely by the distrust kernel. The novel component is the RECIPROCAL trust ramp: credibility of high-validity experts is not linearly restored with position but GEOMETRICALLY amplified, t_j = t0 * (t1/t0)^((j/(n-1))^kappa), with a near-zero early-trust floor t0 in [0.00, 0.12], a super-unity late trust residue t1 in [1.0, 1.6], and a sub-unity exponent kappa in [0.6, 1.2] so trust recovers early in the tail. Early trusted claims are therefore almost completely discounted (reciprocal distrust of front-loaded authority), while LATE high-validity experts are amplified ABOVE the flat share — the key lever for final-expert following without raising the early floor. Weights combine multiplicatively, w_j proportional to g_j * [t_j*(1-tau)/n + tau*inv_j]; evidence d = sum_j w_j*sign(A_j - B_j) is integrated additively over discriminating cues; choice is logistic in beta*d with a uniform lapse epsilon, both attenuated (beta in [2.8, 4.0], epsilon in [0.12, 0.18]) to avoid over-commitment on allegiance metrics.

`predict(parameters, state, history) -> np.ndarray`:
def predict(parameters, state, history):
    # RTDT: Reciprocal-Trust Distrust Tallying.
    # Replaces PGDT (pi_7) per the arbiter's directive. Three quantified
    # departures from the accepted PBDT base, each targeted at a
    # documented residual:
    #   (A) STEEPER DISTRUST KERNEL: gamma [2.6,2.9] -> [3.0, 4.2],
    #       tau [0.91,0.93] -> [0.92, 0.96]. Repairs the under-predicted
    #       anti-validity slope (Exp5/Exp3 cluster) and lets kernel
    #       dominance weaken count/tally allegiance (Exp4, Exp2).
    #   (B) RECIPROCAL TRUST RAMP: replaces the linear ramp with a
    #       geometric one, t_j = t0 * (t1/t0)^((j/(n-1))^kappa), with a
    #       NEAR-ZERO early floor t0 in [0.00, 0.12] and a SUPER-UNITY
    #       late residue t1 in [1.0, 1.6], kappa in [0.6, 1.2]. Fixes
    #       Exp16's over-predicted primacy-rescue (early trusted experts
    #       now carry almost no trusted-channel weight) and Exp8/Exp10's
    #       under-followed late 0.90-validity expert (late trusted
    #       experts are AMPLIFIED above the flat share).
    #   (C) ATTENUATED CHOICE RULE: beta [2.8, 4.0], epsilon [0.12, 0.18],
    #       since the distrust family systematically over-commits on
    #       allegiance metrics (Exps 4, 6, 9).
    # Gate retained at the moderate steep/low-floor corner the PBDT
    # trajectory verified: eta [4.5, 6.5], delta [0.15, 0.30].
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            f"RTDT expects a (2, n_features) stimulus; got shape {stim.shape}."
        )
    a, b = stim[0], stim[1]
    n = int(stim.shape[1])

    v = np.asarray(parameters["validities"], dtype=float).ravel()
    if v.shape[0] != n:
        # Graceful fallback: strictly decreasing validities.
        v = np.linspace(0.95, 0.55, n)
    v = np.clip(v, 0.0, 1.0)

    tau = float(parameters["tau"])        # distrust share (HIGH, steepened)
    eta = float(parameters["eta"])        # primacy-gate convexity (moderate-steep)
    delta = float(parameters["delta"])    # primacy-gate floor (low)
    gamma = float(parameters["gamma"])    # distrust-inversion steepness (STEEP)
    c = float(parameters["c"])            # partial centering of error rates
    t0 = float(parameters["t0"])          # early-trust floor (NEAR ZERO)
    t1 = float(parameters["t1"])          # late-trust residue (SUPER-UNITY)
    kappa = float(parameters["kappa"])    # reciprocal-ramp exponent (SUB-UNITY)
    beta = float(parameters["beta"])      # choice consistency (ATTENUATED)
    eps = float(parameters["epsilon"])    # uniform lapse (ATTENUATED)

    # (1) DISTRUST INVERSION with partial centering: treat the stated
    # validity as an error rate; subtract a fraction c of the smallest
    # error rate before raising to the (now steeper) gamma power, then
    # normalize. gamma in [3.0, 4.2] with tau in [0.92, 0.96] makes the
    # distrust kernel the dominant carrier of the anti-validity
    # gradient in validity-position-confounded layouts.
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
        # (2) RECIPROCAL TRUST RAMP, computed in log space for numerical
        # stability: log t_j = log t0 + (j/(n-1))^kappa * (log t1 - log t0).
        # With t0 ~ 0 the early positions are pinned at near-zero trust
        # (reciprocal distrust of front-loaded authority), and because
        # kappa < 1 the normalized-position exponent rises quickly, trust
        # recovers early in the tail and the LAST positions exceed the
        # flat share (t1 > 1) -- late trusted experts are amplified.
        t0_eff = max(t0, 1e-4)  # guard the geometric form against t0 = 0
        t1_eff = max(t1, 1e-4)
        frac = np.power(pos / (n - 1.0), kappa)  # in [0, 1], concave-leaning
        t = np.exp(np.log(t0_eff) + frac * (np.log(t1_eff) - np.log(t0_eff)))
        # (3) STEEP FLOORED CONVEX PRIMACY GATE at the moderate corner:
        # eta in [4.5, 6.5], delta in [0.15, 0.30].
        g = delta + (1.0 - delta) * np.power((n - pos) / (n - 1.0), eta)
    else:
        t = np.array([1.0])
        g = np.array([1.0])

    # (4) MULTIPLICATIVE combination: the gate scales the bracket
    # cue-by-cue. The trusted channel is modulated by the reciprocal
    # ramp -- near-vanishing early, super-unity late -- while the steep
    # distrust kernel (tau >= 0.92) dominates the bracket elsewhere.
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

    # (6) Numerically stable logistic choice rule -- beta in [2.8, 4.0]
    # (attenuated: the distrust family over-commits on allegiance
    # metrics), with a uniform lapse epsilon in [0.12, 0.18].
    p_a = 0.5 * (1.0 + np.tanh(0.5 * beta * d))
    probs = np.array([p_a, 1.0 - p_a], dtype=float)
    probs = (1.0 - eps) * probs + eps * 0.5
    return probs

`policy(probs) -> int`:
def policy(probs):
    probs = np.asarray(probs, dtype=np.float64)
    probs = probs / probs.sum()  # guard against float drift
    return int(np.random.choice(len(probs), p=probs))

`parameters`:
- tau: [0.92, 0.96]
- eta: [4.5, 6.5]
- delta: [0.15, 0.30]
- gamma: [3.0, 4.2]
- c: [0.05, 0.25]
- t0: [0.0, 0.12]
- t1: [1.0, 1.6]
- kappa: [0.6, 1.2]
- beta: [2.8, 4.0]
- epsilon: [0.12, 0.18]
- validities: validities

`rationale`:
RTDT implements the arbiter's prescription exactly, repairing the three documented mechanistic failures of the pi_7/pi_9 distrust family with three quantified, independently falsifiable levers. (1) STEEPER DISTRUST KERNEL (gamma [3.0, 4.2], tau [0.92, 0.96]): both current theories under-predict the anti-validity slope (Exp5 observed -0.576 vs PBDT -0.418, PGDT -0.438) and under-shoot the position-crossover composite (Exp15). A steeper inversion concentrates even more bracket mass on low-validity error-rate cues, deepening the anti-validity regression toward the observed value, while the stronger kernel dominance automatically weakens count/tally allegiance toward Exp4's observed 0.843 and Exp2's 0.158. (2) RECIPROCAL TRUST RAMP: PBDT's linear ramp with t0 in [0.25, 0.35] leaves the early trusted expert with 25-35% of the flat share, which is why PBDT over-predicts primacy-rescue (Exp16: 0.371 vs observed 0.322; PGDT 0.292 is closer but its flat trusted channel is position-independent, which Exp18 decisively rejects: PGDT +1.86 vs observed -0.93). The reciprocal form t_j = t0*(t1/t0)^((j/(n-1))^kappa) with t0 in [0.00, 0.12] crushes early trusted weight toward zero (fixing Exp16's rescue rate and further crushing Exp14's trusted-early side) while the super-unity t1 in [1.0, 1.6] with sub-unity kappa AMPLIFIES late trusted experts above the flat share -- the only structural channel that can lift Exp8's final 0.90-validity following (observed 0.396 vs PBDT 0.279) and Exp10's FEDI-adjacent signature without raising the early floor. (3) ATTENUATED CHOICE RULE (beta [2.8, 4.0], epsilon [0.12, 0.18]): the distrust family systematically over-commits on allegiance metrics (Exp4: 0.879 vs 0.843; Exp7: 0.857 vs 0.788; Exp9: 0.295 vs 0.341 needs less determinism in the recency direction); softer noise pulls all of these toward target at a small cost on slope metrics that the steeper kernel and amplified late trust compensate. The gate stays at the moderate steep/low-floor corner (eta [4.5, 6.5], delta [0.15, 0.30]) that the PBDT ACCEPTED trajectory verified, so Exps 1, 13, 15, 17 -- where PBDT already succeeds -- are structurally preserved. The reciprocal ramp is computed in log space with a 1e-4 guard on t0 so the [0.00, 0.12] range including exact zero remains numerically valid. Falsifiable predictions: Exp16 rescue rate near 0.10-0.20 (currently 0.371/0.292), Exp8 FEDI near 0.38-0.45 (currently ~0.28), Exp4 allegiance near 0.82-0.86, with Exp18's negative early-trusted contrast retained (the near-zero t0 pushes the PBDT-style crushed early-trusted channel even further toward the observed -0.93).

## LOSS TRAJECTORY (this propose-loop)
Aggregate loss across iterations of THIS propose-loop (lower = better, 0 = perfect, `+inf` = unscorable). The ACCEPTED / REJECTED tag is the loop's programmatic accept-gate decision: `loss < accepted_loss` -> ACCEPTED (becomes new base), else REJECTED (base unchanged). Use this together with the per-experiment values below to grade fit-quality AND your own past advice (see `## YOUR PRIOR CRITIQUES` below).

- iter 1 (current candidate you are grading): loss=0.0830 -> ACCEPTED
Running-best (last accepted) base: iter 1 at loss=0.0830.

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
**Candidate (simulated) value:** 0.1467 (var=0.0022)
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
- pi_9: 0.1423 (var=0.0016)

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
**Candidate (simulated) value:** 0.3042 (var=0.0064)
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
- pi_9: 0.3146 (var=0.0051)

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
**Candidate (simulated) value:** -0.6225 (var=0.0132)
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
- pi_9: -0.4178 (var=0.0203)

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
**Candidate (simulated) value:** 0.8358 (var=0.0058)
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
- pi_9: 0.8792 (var=0.0043)

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
**Candidate (simulated) value:** 0.1959 (var=0.0028)
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
- pi_9: 0.1894 (var=0.0018)

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
**Candidate (simulated) value:** 0.3450 (var=0.0017)
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
- pi_9: 0.3208 (var=0.0017)

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
**Candidate (simulated) value:** 0.8178 (var=0.0032)
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
- pi_9: 0.8572 (var=0.0032)

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
**Candidate (simulated) value:** 0.3082 (var=0.0042)
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
- pi_9: 0.2789 (var=0.0034)

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
**Candidate (simulated) value:** 0.3275 (var=0.0035)
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
- pi_9: 0.2954 (var=0.0028)

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
**Candidate (simulated) value:** -0.2276 (var=0.0108)
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
- pi_9: -0.2701 (var=0.0071)

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
**Candidate (simulated) value:** 0.2360 (var=0.0066)
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
- pi_9: 0.2873 (var=0.0067)

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
**Candidate (simulated) value:** 0.3941 (var=0.0372)
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
- pi_9: 0.5986 (var=0.0372)

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
**Candidate (simulated) value:** 1.4278 (var=0.0964)
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
- pi_9: 1.6694 (var=0.1653)

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
**Candidate (simulated) value:** 0.3306 (var=0.0122)
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
- pi_9: 0.2639 (var=0.0052)

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
**Candidate (simulated) value:** 0.9356 (var=0.1521)
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
- pi_9: 1.0273 (var=0.1192)

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
**Candidate (simulated) value:** 0.3575 (var=0.0141)
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
- pi_9: 0.3709 (var=0.0137)

### Experiment 17
**Design**
  A=[1, 1, 1, 1, 1, 0]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 0, 1]  B=[1, 0, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0, 1]
  A=[1, 1, 1, 0, 1, 1]  B=[1, 1, 0, 1, 1, 1]
  A=[1, 1, 0, 1, 1, 1]  B=[1, 1, 1, 0, 1, 1]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[0, 0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 0, 1, 1, 1, 1]  B=[0, 1, 1, 1, 0, 1]
  A=[0, 1, 1, 1, 0, 1]  B=[1, 0, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 0, 0]  B=[1, 0, 1, 1, 1, 1]
  A=[1, 1, 0, 0, 1, 1]  B=[0, 0, 1, 1, 0, 0]
  A=[0, 0, 1, 1, 0, 0]  B=[1, 1, 0, 0, 1, 1]
  A=[1, 1, 0, 1, 1, 1]  B=[0, 1, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 1]  B=[1, 1, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 1, 0]  B=[1, 0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 0, 1]  B=[1, 0, 1, 1, 1, 0]
  A=[1, 0, 1, 1, 1, 0]  B=[0, 1, 1, 1, 0, 1]

**Metric**
```python
import numpy as np
import pandas as pd

_CACHE = {}

_TRIALS = [
    ((1, 1, 1, 1, 1, 0), (0, 1, 1, 1, 1, 1)),
    ((0, 1, 1, 1, 1, 1), (1, 1, 1, 1, 1, 0)),
    ((1, 1, 1, 1, 0, 1), (1, 0, 1, 1, 1, 1)),
    ((1, 0, 1, 1, 1, 1), (1, 1, 1, 1, 0, 1)),
    ((1, 1, 1, 0, 1, 1), (1, 1, 0, 1, 1, 1)),
    ((1, 1, 0, 1, 1, 1), (1, 1, 1, 0, 1, 1)),
    ((1, 1, 1, 1, 0, 0), (0, 0, 1, 1, 1, 1)),
    ((0, 0, 1, 1, 1, 1), (1, 1, 1, 1, 0, 0)),
    ((1, 1, 1, 0, 0, 0), (0, 0, 0, 1, 1, 1)),
    ((0, 0, 0, 1, 1, 1), (1, 1, 1, 0, 0, 0)),
    ((1, 0, 1, 1, 1, 1), (0, 1, 1, 1, 0, 1)),
    ((0, 1, 1, 1, 0, 1), (1, 0, 1, 1, 1, 1)),
    ((1, 0, 1, 1, 1, 1), (1, 1, 1, 1, 0, 0)),
    ((1, 1, 1, 1, 0, 0), (1, 0, 1, 1, 1, 1)),
    ((1, 1, 0, 0, 1, 1), (0, 0, 1, 1, 0, 0)),
    ((0, 0, 1, 1, 0, 0), (1, 1, 0, 0, 1, 1)),
    ((1, 1, 0, 1, 1, 1), (0, 1, 1, 1, 1, 1)),
    ((0, 1, 1, 1, 1, 1), (1, 1, 0, 1, 1, 1)),
    ((1, 1, 1, 1, 1, 1), (0, 0, 0, 0, 0, 0)),
    ((0, 0, 0, 0, 0, 0), (1, 1, 1, 1, 1, 1)),
    ((1, 0, 1, 1, 1, 1), (1, 1, 1, 1, 1, 0)),
    ((1, 1, 1, 1, 1, 0), (1, 0, 1, 1, 1, 1)),
    ((0, 1, 1, 1, 0, 1), (1, 0, 1, 1, 1, 0)),
    ((1, 0, 1, 1, 1, 0), (0, 1, 1, 1, 0, 1)),
]

_V = np.array([0.95, 0.85, 0.60, 0.60, 0.85, 0.95])
_A = np.array([t[0] for t in _TRIALS], dtype=float)
_B = np.array([t[1] for t in _TRIALS], dtype=float)
_SIGN = np.sign(_A - _B)

_PG_LO = np.array([0.82, 4.0, 0.20, 2.8, 0.10, 2.5, 0.06])
_PG_HI = np.array([0.92, 6.0, 0.45, 3.5, 0.25, 6.0, 0.15])
_PB_LO = np.array([0.91, 6.5, 0.15, 2.6, 0.05, 0.25, 0.95, 0.80, 3.6, 0.11])
_PB_HI = np.array([0.93, 8.0, 0.25, 2.9, 0.25, 0.35, 1.00, 1.50, 4.4, 0.14])


def _pgdt_pvec(par):
    tau, eta, delta, gamma, c, beta, eps = par
    tau = float(tau); eta = float(eta); delta = float(delta)
    gamma = float(gamma); c = float(c); beta = float(beta); eps = float(eps)
    n = 6
    err = 1.0 - _V
    centered = np.maximum(err - c * float(err.min()), 0.0)
    inv = np.power(centered, gamma)
    Zv = float(inv.sum())
    if Zv > 1e-12:
        w_inv = inv / Zv
    else:
        w_inv = np.full(n, 1.0 / n)
    pos = np.arange(n, dtype=float)
    g = delta + (1.0 - delta) * np.power((n - pos) / (n - 1.0), eta)
    bracket = (1.0 - tau) / n + tau * w_inv
    raw = g * bracket
    w = raw / float(raw.sum())
    d = _SIGN.dot(w)
    p = 0.5 * (1.0 + np.tanh(0.5 * beta * d))
    return (1.0 - eps) * p + eps * 0.5


def _pbdt_pvec(par):
    tau, eta, delta, gamma, c, t0, t1, kappa, beta, eps = par
    tau = float(tau); eta = float(eta); delta = float(delta)
    gamma = float(gamma); c = float(c); t0 = float(t0); t1 = float(t1)
    kappa = float(kappa); beta = float(beta); eps = float(eps)
    n = 6
    err = 1.0 - _V
    centered = np.maximum(err - c * float(err.min()), 0.0)
    inv = np.power(centered, gamma)
    Zv = float(inv.sum())
    if Zv > 1e-12:
        w_inv = inv / Zv
    else:
        w_inv = np.full(n, 1.0 / n)
    pos = np.arange(n, dtype=float)
    t = t0 + (t1 - t0) * np.power(pos / (n - 1.0), kappa)
    g = delta + (1.0 - delta) * np.power((n - pos) / (n - 1.0), eta)
    bracket = t * (1.0 - tau) / n + tau * w_inv
    raw = g * bracket
    w = raw / float(raw.sum())
    d = _SIGN.dot(w)
    p = 0.5 * (1.0 + np.tanh(0.5 * beta * d))
    return (1.0 - eps) * p + eps * 0.5


def _make_grid(lo, hi, n_random=192, seed=1234567):
    lo = np.asarray(lo, dtype=float)
    hi = np.asarray(hi, dtype=float)
    k = len(lo)
    m = 2 ** k
    idx = np.arange(m)
    bits = ((idx[:, None] >> np.arange(k)[None, :]) & 1).astype(float)
    corners = lo[None, :] * (1.0 - bits) + hi[None, :] * bits
    center = ((lo + hi) / 2.0)[None, :]
    rng = np.random.default_rng(seed)
    rnd = rng.uniform(lo, hi, size=(n_random, k))
    return np.vstack([corners, center, rnd])


def _weights():
    if 'wmap' in _CACHE:
        return _CACHE['wmap']
    pg_grid = _make_grid(_PG_LO, _PG_HI)
    pb_grid = _make_grid(_PB_LO, _PB_HI)
    nt = len(_TRIALS)
    p_pg = np.zeros(nt)
    for par in pg_grid:
        p_pg += _pgdt_pvec(par)
    p_pg /= float(len(pg_grid))
    p_pb = np.zeros(nt)
    for par in pb_grid:
        p_pb += _pbdt_pvec(par)
    p_pb /= float(len(pb_grid))
    p_pg = np.clip(p_pg, 0.02, 0.98)
    p_pb = np.clip(p_pb, 0.02, 0.98)
    lA = np.log(p_pg / p_pb)
    lB = np.log((1.0 - p_pg) / (1.0 - p_pb))
    wmap = {}
    for i in range(nt):
        wmap[_TRIALS[i]] = (float(lA[i]), float(lB[i]))
    _CACHE['wmap'] = wmap
    return wmap


def _to_tuple(x):
    if isinstance(x, (list, tuple, np.ndarray)):
        return tuple(int(round(float(v))) for v in x)
    s = str(x).replace("'", "").replace('"', '')
    s = s.strip().strip('[](){} ').replace(',', ' ')
    return tuple(int(round(float(p))) for p in s.split())


def metric(data: pd.DataFrame) -> float:
    wmap = _weights()
    if len(data) == 0:
        return 0.0
    ra = data['option_a_ratings'].apply(_to_tuple)
    rb = data['option_b_ratings'].apply(_to_tuple)
    resp = pd.to_numeric(data['response']).to_numpy()
    total = 0.0
    for (a, b), r in zip(zip(ra, rb), resp):
        pr = wmap.get((a, b))
        if pr is None:
            continue
        total += pr[0] if int(r) == 0 else pr[1]
    return float(total)
```

**Observed (real) value:** -9.1163 (var=0.3521)
**Candidate (simulated) value:** -8.6363 (var=0.3496)
**Other theories' values on this metric (for reference):**
- pi_7: 12.6306 (var=0.4648)
- pi_9: -8.3125 (var=0.4421)
- pi_1: 141.4785 (var=0.4190)
- pi_2: 89.6874 (var=0.3151)
- pi_3: 70.0949 (var=0.4149)
- pi_4: 73.0610 (var=0.3610)
- pi_5: 31.8064 (var=0.3769)
- pi_5_1: 27.1285 (var=0.3245)
- pi_6: 41.4469 (var=0.3949)
- pi_8: -23.1646 (var=0.3828)

### Experiment 18
**Design**
  A=[0, 0, 1, 0, 0, 0]  B=[1, 0, 0, 1, 0, 0]
  A=[1, 0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 0, 0]
  A=[0, 1, 0, 1, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 1]
  A=[0, 0, 0, 1, 0, 1]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[1, 0, 0, 1, 0, 1]
  A=[1, 0, 0, 1, 0, 1]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 0, 1]
  A=[0, 1, 0, 1, 0, 1]  B=[0, 0, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[1, 0, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 1]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 0]
  A=[1, 1, 0, 0, 0, 1]  B=[0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 1, 0]  B=[1, 1, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0, 1]  B=[0, 0, 1, 1, 1, 0]
  A=[0, 0, 1, 1, 1, 0]  B=[1, 1, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 1, 1]  B=[0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0]  B=[1, 1, 1, 1, 1, 1]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    """
    Early-trusted-channel contrast score (PBDT vs PGDT diagnostic).

    The design's decisive lever is the TRUSTED (flat-share) channel: PGDT's
    bracket (1-tau)/n + tau*inv_j is position-independent, so an early
    high-validity expert carries the full amplified position-1 gate weight;
    PBDT multiplies the flat share by a trust ramp rising from a low floor
    t0, crushing the early trusted weight by ~1/t0 while leaving late trusted
    experts nearly intact.  Behaviorally this shows up as a specific pattern
    of mirror-corrected choice probabilities across the R1/R1p/R2/R2p/S1/S2/
    S6/T16/T26/T12 cells (and weakly on the anchors).

    This metric computes, for every one of the 32 fixed trial pairs, the
    predicted P(choose A) under PGDT and under PBDT (both engines
    implemented below, each averaged over five parameter settings spanning
    its box), takes the per-trial contrast c_k = p_PGDT - p_PBDT, and scores
    the observed choices against that contrast:

        S = sum_rows c_k * y,   y = +1 if A chosen, -1 if B chosen
        z = S / sqrt(sum_rows c_k^2)

    z is the standardized behavioral expression of the early-trusted
    channel (positive = choices follow PGDT's strong early-trusted
    weighting; near zero / negative = choices follow PBDT's crushed
    early-trusted channel).  Because a single subject contributes only 6
    trials per cell and the per-trial contrast is small, the single-subject
    z is dominated by binomial noise; we therefore report an empirical-Bayes
    shrunken version

        metric = (n / (n + K)) * z,   K = 2000 pseudo-observations,

    which pulls sparse single-subject estimates strongly toward 0 (chance)
    while leaving the full pooled dataset (n ~ 2400) essentially
    unregularized.  The statistic is well defined on any slice of the data.
    """
    V = (0.95, 0.95, 0.75, 0.75, 0.60, 0.95)
    TRIALS = [
        ((0, 0, 1, 0, 0, 0), (1, 0, 0, 1, 0, 0)),
        ((1, 0, 0, 1, 0, 0), (0, 0, 1, 0, 0, 0)),
        ((0, 0, 1, 0, 0, 0), (0, 1, 0, 1, 0, 0)),
        ((0, 1, 0, 1, 0, 0), (0, 0, 1, 0, 0, 0)),
        ((0, 0, 1, 0, 0, 0), (0, 0, 0, 1, 0, 1)),
        ((0, 0, 0, 1, 0, 1), (0, 0, 1, 0, 0, 0)),
        ((0, 0, 1, 0, 0, 0), (1, 0, 0, 1, 0, 1)),
        ((1, 0, 0, 1, 0, 1), (0, 0, 1, 0, 0, 0)),
        ((0, 0, 1, 0, 0, 0), (0, 1, 0, 1, 0, 1)),
        ((0, 1, 0, 1, 0, 1), (0, 0, 1, 0, 0, 0)),
        ((1, 0, 1, 0, 0, 0), (0, 0, 0, 1, 0, 0)),
        ((0, 0, 0, 1, 0, 0), (1, 0, 1, 0, 0, 0)),
        ((0, 1, 1, 0, 0, 0), (0, 0, 0, 1, 0, 0)),
        ((0, 0, 0, 1, 0, 0), (0, 1, 1, 0, 0, 0)),
        ((0, 0, 1, 0, 0, 1), (0, 0, 0, 1, 0, 0)),
        ((0, 0, 0, 1, 0, 0), (0, 0, 1, 0, 0, 1)),
        ((1, 0, 0, 0, 0, 0), (0, 0, 0, 0, 0, 1)),
        ((0, 0, 0, 0, 0, 1), (1, 0, 0, 0, 0, 0)),
        ((0, 1, 0, 0, 0, 0), (0, 0, 0, 0, 0, 1)),
        ((0, 0, 0, 0, 0, 1), (0, 1, 0, 0, 0, 0)),
        ((1, 0, 0, 0, 0, 0), (0, 1, 0, 0, 0, 0)),
        ((0, 1, 0, 0, 0, 0), (1, 0, 0, 0, 0, 0)),
        ((0, 0, 1, 0, 0, 0), (0, 0, 0, 1, 0, 0)),
        ((0, 0, 0, 1, 0, 0), (0, 0, 1, 0, 0, 0)),
        ((0, 0, 0, 0, 1, 0), (0, 0, 1, 0, 0, 0)),
        ((0, 0, 1, 0, 0, 0), (0, 0, 0, 0, 1, 0)),
        ((1, 1, 0, 0, 0, 1), (0, 0, 0, 0, 1, 0)),
        ((0, 0, 0, 0, 1, 0), (1, 1, 0, 0, 0, 1)),
        ((1, 1, 0, 0, 0, 1), (0, 0, 1, 1, 1, 0)),
        ((0, 0, 1, 1, 1, 0), (1, 1, 0, 0, 0, 1)),
        ((1, 1, 1, 1, 1, 1), (0, 0, 0, 0, 0, 0)),
        ((0, 0, 0, 0, 0, 0), (1, 1, 1, 1, 1, 1)),
    ]

    v = np.asarray(V, dtype=float)
    err = 1.0 - v
    pos = np.arange(6, dtype=float)

    def pgdt_w(tau, eta, delta, gamma, c):
        # PGDT weights: floored convex primacy gate x position-independent
        # bracket (flat share + distrust kernel).
        cen = np.maximum(err - c * float(err.min()), 0.0)
        inv = cen ** gamma
        w_inv = inv / inv.sum()
        g = delta + (1.0 - delta) * ((6.0 - pos) / 5.0) ** eta
        br = (1.0 - tau) / 6.0 + tau * w_inv
        raw = g * br
        return raw / raw.sum()

    def pbdt_w(tau, eta, delta, gamma, c, t0, t1, kappa):
        # PBDT weights: steep low-floored gate x (trust-ramped flat share +
        # distrust kernel).
        cen = np.maximum(err - c * float(err.min()), 0.0)
        inv = cen ** gamma
        w_inv = inv / inv.sum()
        t = t0 + (t1 - t0) * (pos / 5.0) ** kappa
        g = delta + (1.0 - delta) * ((6.0 - pos) / 5.0) ** eta
        br = t * (1.0 - tau) / 6.0 + tau * w_inv
        raw = g * br
        return raw / raw.sum()

    def p_a(w, A, B, beta, eps):
        d = float(np.dot(w, np.sign(np.asarray(A, dtype=float) - np.asarray(B, dtype=float))))
        p = 0.5 * (1.0 + np.tanh(0.5 * beta * d))
        return (1.0 - eps) * p + 0.5 * eps

    # Parameter settings spanning each theory's box (midpoint, key-dim
    # variants, weak corner, strong corner).
    PG = [
        (0.87, 5.00, 0.325, 3.15, 0.175, 4.25, 0.105),
        (0.82, 5.00, 0.325, 3.15, 0.175, 4.25, 0.105),
        (0.92, 5.00, 0.325, 3.15, 0.175, 4.25, 0.105),
        (0.92, 4.00, 0.200, 2.80, 0.100, 2.50, 0.150),
        (0.82, 6.00, 0.450, 3.50, 0.250, 6.00, 0.060),
    ]
    PB = [
        (0.92, 7.25, 0.20, 2.75, 0.15, 0.30, 0.975, 1.15, 4.00, 0.125),
        (0.91, 7.25, 0.20, 2.75, 0.15, 0.25, 0.975, 1.15, 4.00, 0.125),
        (0.93, 7.25, 0.20, 2.75, 0.15, 0.35, 0.975, 1.15, 4.00, 0.125),
        (0.93, 6.50, 0.25, 2.60, 0.05, 0.35, 0.950, 1.50, 3.60, 0.140),
        (0.91, 8.00, 0.15, 2.90, 0.25, 0.25, 1.000, 0.80, 4.40, 0.110),
    ]

    pg_ws = [pgdt_w(s[0], s[1], s[2], s[3], s[4]) for s in PG]
    pb_ws = [pbdt_w(s[0], s[1], s[2], s[3], s[4], s[5], s[6], s[7]) for s in PB]

    contrast = {}
    for A, B in TRIALS:
        pG = float(np.mean([p_a(w, A, B, s[5], s[6]) for (w, s) in zip(pg_ws, PG)]))
        pB = float(np.mean([p_a(w, A, B, s[8], s[9]) for (w, s) in zip(pb_ws, PB)]))
        contrast[(A, B)] = pG - pB

    def as_key(x):
        return tuple(int(round(float(t))) for t in x)

    n = int(len(data))
    if n == 0:
        return 0.0

    S = 0.0
    Q = 0.0
    for a, b, r in zip(data['option_a_ratings'], data['option_b_ratings'],
                        data['response']):
        key = (as_key(a), as_key(b))
        c = contrast.get(key)
        if c is None:
            continue
        if abs(c) < 1e-12:
            continue
        y = 1.0 if int(round(float(r))) == 0 else -1.0  # +1 = chose A
        S += c * y
        Q += c * c

    if Q <= 1e-24:
        return 0.0

    z = S / np.sqrt(Q)
    # Empirical-Bayes shrinkage toward 0 (chance-level expression of the
    # contrast) with a fixed pseudo-observation count: single-subject
    # slices (n=96) are shrunk hard; the full pooled dataset (n~2400) is
    # dominated by the data.
    lam = float(n) / (float(n) + 2000.0)
    return float(lam * z)
```

**Observed (real) value:** -0.9319 (var=0.0016)
**Candidate (simulated) value:** -0.9673 (var=0.0016)
**Other theories' values on this metric (for reference):**
- pi_9: -1.5890 (var=0.0021)
- pi_7: 1.8638 (var=0.0018)
- pi_1: 18.9139 (var=0.0033)
- pi_2: 18.1537 (var=0.0025)
- pi_3: 7.5747 (var=0.0025)
- pi_4: 9.8800 (var=0.0020)
- pi_5: 0.9857 (var=0.0019)
- pi_5_1: 0.3211 (var=0.0019)
- pi_6: 5.4088 (var=0.0025)
- pi_8: -4.8657 (var=0.0019)

## RESPONSE FORMAT

Return a JSON object with the following fields:
- interpretation: Freeform analysis of the model simulation results on existing experiments and how they do or do not support the proposed model/theory.
- verdict: Either 'regenerate' (regenerate a new model/theory) or 'continue' (keep the current model/theory).
- rationale: If verdict='regenerate', why the current predict / policy / parameter-ranges should be revised. If verdict='continue', a sketch of why the current theory should be kept.


## Response

```json
{
  "interpretation": "The candidate faithfully implements the arbiter's RTDT prescription (steep distrust kernel, reciprocal trust ramp with near-zero t0 and super-unity t1, attenuated choice rule, moderate primacy gate), and the gate ACCEPTED it at loss 0.0830. Per-experiment diagnosis: (i) Clear wins vs the pi_7 base \u2014 Exp3 anti-validity slope (-0.6225 vs pi_7's -0.4381, obs -0.5756), Exp6 (0.345 vs 0.303, obs 0.374), Exp7 (0.818 vs 0.844, obs 0.788), Exp9 (0.328 vs 0.299, obs 0.341), Exp13 (1.428 vs 1.190, obs 1.836), Exp14 (0.331 vs 0.431, obs 0.132), Exp15/16/17/18 all close to observed. (ii) Remaining systematic misses, judged against the between-subject variance: **Exp14 primacy-rescue is still ~2.1 SD too high** (0.3306 vs 0.1322; the arbiter's own falsifiable target was 0.10\u20130.20) \u2014 the early trusted channel is evidently not crushed enough at the fitted parameters, likely because t0 sat near its 0.12 ceiling and/or the gate corner is too soft. **Exp2 tally-allegiance is ~2 SD too high** (0.3042 vs 0.1583, essentially unchanged from pi_7's 0.2996 \u2014 the 'steeper gamma weakens allegiance' prediction did not materialize). **Exp8 FEDI undershoots** (0.3082 vs 0.3957; arbiter target 0.38\u20130.45) \u2014 the model anti-follows the final 0.90-validity expert too strongly. **Exp3 now slightly OVERSHOOTS** the anti-validity slope (-0.6225 vs -0.5756), and Exp5 adherence undershoots (0.196 vs 0.231) \u2014 both signs that gamma/tau over-steepened past their target. Exp12 (0.394 vs 0.540) and Exp11 (0.236 vs 0.315) undershoot the primacy slope, consistent with the reciprocal ramp flattening the g_j*t_j product on validity-matched cells, but both diffs are within 1 SD of the between-subject variance, so I weight them lightly. Critically, the overshoot on Exp3/Exp5/Exp8 points to a coherent single knob: gamma is too high, and lowering it simultaneously (a) pulls Exp3 back to -0.58, (b) lifts Exp5 toward 0.231, (c) reduces the over-anti-following of the high-validity final expert in Exp8, and (d) restores some high-validity (pro-TTB) weight that would soften Exp2's tally contrast \u2014 without touching the trusted-channel architecture that won Exp17/18.",
  "verdict": "regenerate",
  "rationale": "The candidate is accepted and becomes the base, but two >2SD residuals (Exp14, Exp2) plus a consistent over-steepening signature (Exp3 overshoot, Exp5/Exp8 undershoot) leave identifiable in-family gains. Keep the RTDT architecture verbatim and retune three knobs: (1) **Crush the early trusted floor harder**: narrow t0 from [0.00, 0.12] to [0.00, 0.05] (and check where the fit landed \u2014 the 0.33 rescue rate implies the optimizer used a soft corner). This is the direct lever on Exp14's 0.33-vs-0.13 miss and further secures Exp18's negative early-trusted contrast. Do NOT raise t0 to help Exp2 \u2014 that would undo Exp14; the Exp2/Exp14 conflict must be resolved on the kernel/noise side, not the trust side. (2) **Back off the kernel steepness**: gamma from [3.0, 4.2] down to roughly [2.7, 3.3] (tau can stay in [0.92, 0.96] or slip to [0.91, 0.95]). The steepening overshot its own target: Exp3 went from -0.44 to -0.62 past the observed -0.58, Exp5 adherence fell to 0.196 below the observed 0.231, and Exp8's final 0.90-expert is anti-followed too hard (0.308 vs 0.396). A slightly flatter kernel adds high-validity weight, which also pulls Exp2's tally contrast down from 0.304 toward 0.158 by restoring a little TTB-side following. (3) **Soften determinism a touch more for Exp2 only if (2) is insufficient**: raise the epsilon ceiling to ~0.20 or lower the beta floor to ~2.5, then verify Exp4 anchors stay >= 0.82 (currently 0.836 vs 0.843, so there is headroom). Optionally widen t1 upward ([1.0, 2.0]) or lower kappa toward [0.5, 0.9] to strengthen the late-trusted amplification for Exp8 without touching the early floor. Preserve the moderate gate corner (eta [4.5, 6.5], delta [0.15, 0.30]) \u2014 Exp15's composite and the Exp11/12 primacy slopes (already within noise) depend on it, and steepening the gate further would fight the t-ramp and flatten g*t more. Falsifiable checks for the next iteration: Exp14 rescue in [0.10, 0.22], Exp2 contrast in [0.15, 0.24], Exp8 FEDI in [0.35, 0.45], Exp3 slope in [-0.60, -0.54], with Exp4, Exp17, Exp18 held at their current near-perfect values."
}
```

## Usage

```json
{
  "input_tokens": 51319,
  "output_tokens": 9129,
  "reasoning_tokens": 6299,
  "provider": "Reka"
}
```
