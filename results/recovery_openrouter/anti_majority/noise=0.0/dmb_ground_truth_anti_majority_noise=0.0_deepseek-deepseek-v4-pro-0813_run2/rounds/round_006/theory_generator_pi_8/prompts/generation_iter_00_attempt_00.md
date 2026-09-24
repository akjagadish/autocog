# generation_iter_00_attempt_00

## System Prompt

You are a renowned cognitive scientist and an expert Python programmer.

Your job is to propose a new theory and its model instantiation in the Decision Making (Binary Features) domain based on the feedback provided by an arbiter. The feedback contains diagnoses of mechanistic failures of the previous theory along with suggestions for a new theory family that overcomes those failures. The newly proposed theory and model should display human-like behavior when simulated on experiment(s). 
The goal of the theory generation process is to SURFACE theories that are EXPERIMENT-INVARIANT: that is,theories that explain data across the majority of experiments. 
You will see a list of theories that have been proposed in the past but you should only use them as inspiration and not to choose from them. Propose a new theory that is different. 
If they fail to do so, you will receive feedback on their performance on the same experiment(s) and you will have to propose another new theory and model that meet the requirements, iterating until you succeed.

If you think the failure to capture human behavior is due to arbiter feedback that is inaccurate or unhelpful, you can propose a new theory and model that ignore the feedback, but you must provide rationale for why you are ignoring it and how your proposal overcomes the identified mechanistic failures.

## ACCEPT GATE & LOSS TRAJECTORY — HOW THE LOOP HANDLES YOUR EDITS
This propose-loop has a programmatic accept gate: after every iteration the candidate's `aggregate_loss` is compared against the running-best loss; strict improvement -> ACCEPTED (the candidate becomes the new running-best base); otherwise -> REJECTED (the candidate is discarded and the base is unchanged). You do NOT need to manually "revert" a regressed edit — the gate already does that for you.

The block rendered below as `## PREVIOUS CANDIDATE (this loop)` is ALWAYS the running-best (last ACCEPTED) candidate, NEVER your most recent attempt if it was rejected. So:
  * Treat `## PREVIOUS CANDIDATE` as a known-good base. Build on it.
  * The `## LOSS TRAJECTORY` block tags every iteration ACCEPTED or REJECTED. Use this as ground truth on which past critic advice actually moved the loop forward and which didn't.
  * The `## PRIOR FEEDBACK ITERATIONS` block annotates each prior critique with the same ACCEPTED/REJECTED tag of the candidate it elicited. Down-weight critic advice whose previous candidates were REJECTED, and reinforce / extend advice whose candidates were ACCEPTED.
  * Treat the best ACCEPTED iteration's loss as a soft floor — the next edit should plausibly land at-or-below it, otherwise the gate will reject your attempt and the base stays put.

Each metric value below is shown as `point_estimate (var=X)`, where `point_estimate` is `metric(data)` evaluated on the full pooled dataset and `var` is the population (between-subject) variance of the same metric re-applied per `subject_id`. The point estimate is the canonical scalar; `var` reports how consistent that estimate is across subjects (lower = more consistent). `var=n/a` means the metric could not be applied to a single-subject slice.

## PARAMETER NOTATION
`parameters` is a JSON object mapping each parameter name (snake_case string) to a *string* value that specifies its domain. Every value MUST be a string — never a bare list, number, tuple, or expression. Use exactly one of these notations per parameter:

1. Continuous interval — square brackets, two numeric bounds:
   "[min, max]"
   Examples: "[0, 1]", "[1.0, 10.0]", "[10, 1000]"

2. Discrete set — curly braces, comma-separated values:
   "{v1, v2, ...}"
   Example: "{1, 2}"

3. Vector of intervals whose length is set by the experiment — a bracketed tuple repeated by a symbolic length variable:
   "[(min, max)] * length_var"
   Example: "[(0, 1)] * n_features"

4. Symbolic reference — a bare variable name (no brackets, no angle brackets), used when the parameter takes its value from an experiment-defined constant rather than a range:
   "variable_name"
   Example: "n_features"

Rules:
- Do not use parentheses for intervals; square brackets only. Tuples `(a, b)` are reserved for the vector-of-intervals notation in (3).
- Do not mix notations within a single value (e.g., no "[0, 1] or {2, 3}").
- Do not quote numbers inside the notation (write "[0, 1]", not "['0', '1']").
- Every parameter referenced by `predict` or `policy` must appear as a key in `parameters`, and vice versa.
- Notations 3 and 4 may ONLY reference the experiment-defined symbolic identifiers listed under "ALLOWED SYMBOLIC IDENTIFIERS" below. Do not invent new identifier names. If a parameter's shape doesn't fit any of those variables, fall back to a literal interval (notation 1) or discrete set (notation 2). Use these names so the model adapts to any experiment in this domain instead of hardcoding shapes.

## ALLOWED SYMBOLIC IDENTIFIERS (for notations 3 and 4 above)
- n_features: Number of expert ratings per option (LLM-proposed via `validities` length).
- validities: Per-expert validities (LLM-proposed; each in [0.5, 1.0]); fixed across all trials.

## AVAILABLE IMPORTS inside `predict` and `policy`
- numpy as np
- pandas as pd
- scipy and its submodules
- torch and torch.nn.functional as F
- sklearn and its submodules
- math, random, and other standard Python libraries

## RUNTIME CONTRACT (function signatures and argument shapes)
`predict(parameters, state, history) -> np.ndarray`:
- `parameters`: dict[str, value]. One sample drawn from your declared `parameters` ranges, applied for the entire subject run.
- `state`: the per-trial input delivered by the experiment (shape is domain-specific — see the experiment description above and the `history` key list below, which mirrors the per-trial variables carried in `state`). Convert to an array with `np.asarray(state)` if you need array ops.
- `history`: dict-of-lists for past trials in this subject's run, NOT a list-of-dicts. The per-trial keys are:
  Each value below is a Python list in trial order; entry `i` is the value for trial `i`. On the first trial all lists are empty.
  - `"option_a_ratings"`: List of n_features binary expert ratings (each 0 or 1) for option A on this trial.
  - `"option_b_ratings"`: List of n_features binary expert ratings (each 0 or 1) for option B on this trial.
  - `"response"`: 0 if subject chose A, 1 if subject chose B.
Iterating `for x in history:` iterates the dict KEYS (strings); to walk trials index the lists in lock-step, e.g. `for i in range(len(next(iter(history.values())))): ...`.
- Returns: 1-D `np.ndarray` of choice probabilities over the experiment's discrete action set, summing to 1.

`policy(probs) -> int`:
- Receives the probability vector produced by `predict`.
- Returns: integer index in `[0, len(probs))` identifying the chosen action. If you sample with `np.random.choice(..., p=probs)`, normalise first (`probs = np.asarray(probs, dtype=np.float64); probs /= probs.sum()`) to avoid the "probabilities do not sum to 1" ValueError from float drift.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

Each subject completes ~96 trials in a single block, with order randomized independently per subject. On every trial the subject sees two options A and B, each described by `n_features` binary expert ratings (each 0 or 1). The per-feature validities and n_features are fixed per experiment (design-time choices). Validities are communicated to the subject in the instructions. Both `n_features` and `validities` are exposed to your `predict` via the `parameters` dict. The subject chooses A or B; no correctness feedback is provided after the choice.

## ARBITER GUIDE
The arbiter labelled this round's two theories in its recommendation as follows:
- THEORY 1 = `pi_7_1`
- THEORY 2 = `pi_5`
- The recommendation below acts on THEORY 1 (= `pi_7_1`).

Replace THEORY 1 with a conflict-modulated continuous anti-validity theory. Keep a mostly negative subject-level sign and a continuous validity-weighted difference D = sum_j v_j ** gamma_i * (A_j - B_j), but do not impose a fixed threshold and do not use one fixed half-saturation constant. Use an evidence-gated response such as S_i = -lambda_i * G(C) * D / (kappa_i + abs(D) + r_i) + bias_i + w_t * T, where G(C) is a subject-level gain that is large when D is concentrated in one or a few high-validity experts and small when D comes from many low-validity or mutually conflicting experts. C can be an inverse-validity weighted count of disagreeing features or the largest single feature contribution divided by abs(D). A small tally or configural term T = (1/n) * sum_j (A_j - B_j) with a sign-dependent weight should also be included to handle count-driven designs. This theory differs from THEORY 1 by having no dead zone, and differs from THEORY 2 by making gain and saturation depend on conflict structure rather than a fixed tau. The resulting shape can give a strong low-D gradient in the one-hot staircase of Experiment 2, a very negative high-minus-2-low-gap statistic in Experiment 1, and near-zero low-D contrast in the jumbled conflict design of Experiment 14.

## THEORY LEADERBOARD
A small set of prior picked theories shown for reference. Overall score is in `[0, 1]`, higher = better, computed as `1 - L2_norm(normalized_per_experiment_distances) / max_L2_norm`. 1.0 means closest to the real value on every experiment+metric pair; 0.0 means farthest. Each entry below carries the same depth of detail as the PREVIOUS MODEL INSTANCE above so you can borrow concrete mechanisms when useful.

### `pi_5` (overall score: 0.548)

**Description**
Compressive Negative Validity-Weighted integration with subject-level saturation (CNVW-tau). Each subject forms D = sum_j v_j^gamma_i * (A_j - B_j), where v_j are the instructed expert validities and gamma_i is a subject-level validity exponent. The weighted difference is passed through a strongly saturating bounded transform psi(D) = D / (tau_i + abs(D)), with a small subject-level half-saturation constant tau_i. Most subjects apply a negative sign, S_i = -lambda_i * psi(D) + bias_i, while a minority apply a positive sign. Choice probability is p(A) = epsilon_i/2 + (1 - epsilon_i) * sigmoid(beta_i * S_i). There is no feature-tally term and no conflict-gating interaction.

`predict(parameters, state, history) -> np.ndarray`:
import numpy as np

def predict(parameters, state, history):
    """Compressive negative validity-weighted integration with subject-level tau.

    D = sum_j v_j^gamma * (A_j - B_j)
    psi(D) = D / (tau + abs(D))
    S = sign * lambda * psi(D) + bias
    p(A) = lapse/2 + (1-lapse) * sigmoid(beta * S)

    Most subjects use sign = -1; a minority draw sign = +1.
    history is intentionally ignored because there is no feedback.
    """
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            "CNVW-tau expects a (2, n_features) stimulus; "
            f"got shape {stim.shape}."
        )

    a = stim[0]
    b = stim[1]

    v = np.asarray(parameters["validities"], dtype=float)
    if v.size != a.size:
        raise ValueError(
            f"validities length {v.size} does not match n_features {a.size}."
        )

    gamma = float(parameters["gamma"])
    lam = float(parameters["lambda"])
    beta = float(parameters["beta"])
    epsilon = float(parameters["epsilon"])
    bias = float(parameters["bias"])
    p_positive = float(parameters["p_positive"])
    sign_draw = float(parameters["sign_draw"])
    tau = float(parameters["tau"])

    # Latent sign mixture: most subjects use negative-valence weighting;
    # a minority trust positive-valence evidence and get a positive sign.
    sign = 1.0 if sign_draw < p_positive else -1.0

    # Validity-weighted feature difference.
    d = float(np.dot(v ** gamma, a - b))

    # Subject-level strongly saturating bounded transform. The small
    # half-saturation constant tau forces most non-negligible validity-
    # weighted differences toward the sign bound, so sign and not
    # continuous magnitude drives the main choice contrast.
    psi = d / (tau + abs(d))

    score = sign * lam * psi + bias
    z = beta * score

    # Numerically stable sigmoid for p(A | score).
    if z >= 0.0:
        p_a_core = 1.0 / (1.0 + np.exp(-z))
    else:
        ez = np.exp(z)
        p_a_core = ez / (1.0 + ez)

    # Uniform lapse mixture over the two options.
    p_a = (1.0 - epsilon) * p_a_core + epsilon / 2.0
    p_a = float(np.clip(p_a, 0.0, 1.0))

    return np.array([p_a, 1.0 - p_a], dtype=float)

`policy(probs) -> int`:
import numpy as np

def policy(probs):
    p = np.asarray(probs, dtype=float)
    if p.sum() <= 0.0:
        p = np.ones_like(p) / len(p)
    else:
        p = p / p.sum()
    return int(np.random.choice(len(p), p=p))

`parameters`:
- gamma: [1.5, 2.5]
- tau: [0.10, 0.25]
- lambda: [0.8, 2.0]
- beta: [0.8, 2.0]
- bias: [-0.25, 0.25]
- epsilon: [0.03, 0.10]
- p_positive: [0.03, 0.10]
- sign_draw: [0.0, 1.0]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=-0.4323 (var=0.0402) vs this=-0.2852 (var=0.0363)
- Experiment 2: real=-0.2650 (var=0.0713) vs this=-0.2133 (var=0.0171)
- Experiment 3: real=0.3622 (var=0.0979) vs this=0.5467 (var=0.1673)
- Experiment 4: real=0.5300 (var=0.0883) vs this=0.5175 (var=0.0843)
- Experiment 5: real=-0.0300 (var=0.0191) vs this=0.0050 (var=0.0269)
- Experiment 6: real=0.0117 (var=0.0033) vs this=0.0663 (var=0.0100)
- Experiment 7: real=0.0064 (var=0.0161) vs this=0.0393 (var=0.0171)
- Experiment 8: real=0.1200 (var=0.0096) vs this=0.1742 (var=0.0110)
- Experiment 9: real=0.6008 (var=0.0611) vs this=0.4529 (var=0.1083)
- Experiment 10: real=0.0675 (var=0.0553) vs this=-0.0025 (var=0.0475)
- Experiment 11: real=0.3030 (var=0.0429) vs this=0.4985 (var=0.0248)
- Experiment 12: real=0.0356 (var=0.0037) vs this=0.3367 (var=0.0255)
- Experiment 13: real=-0.5133 (var=0.1804) vs this=-0.1583 (var=0.0665)
- Experiment 14: real=0.3889 (var=0.0632) vs this=0.2444 (var=0.0354)


---

### `pi_7_1` (overall score: 0.366)

**Description**
Thresholded anti-validity utility with Gaussian threshold noise and a small validity-consistent soft leak (TAVU-tn). Subjects compute a validity-weighted difference D = sum_j v_j^gamma_i * (A_j - B_j). A subject-level latent sign dominates: most subjects use negative weighting and make the anti-validity choice when |D| exceeds a subject-level threshold tau_i, but threshold placement is noisy across trials, so the aggregate threshold boundary is graded rather than a step. Within the dead zone and below the sign-following ceiling, subjects fall back on a subject-level bias. A small plain-D sigmoidal leak in the validity-consistent direction weakly damps extreme anti choices at large |D|. A uniform lapse adds residual noise. The dominant process remains thresholded sign, not continuous magnitude accumulation.

`predict(parameters, state, history) -> np.ndarray`:
import numpy as np
import math


def predict(parameters, state, history):
    """Thresholded anti-validity utility with Gaussian threshold noise (TAVU-tn).

    D = sum_j v_j^gamma * (A_j - B_j). A subject-level sign dominates:
    most subjects apply a negative validity weighting and choose the
    anti-validity option when |D| exceeds a subject-level threshold.
    Threshold placement is noisy across trials, implemented analytically
    as p_above = Phi((|D| - tau) / tau_sd). Inside the dead zone, and
    below the sign-following ceiling, choices fall back on a subject-level
    bias. A small plain-D sigmoidal leak weakly opposes the anti-validity
    sign at large |D|, and a uniform lapse adds residual noise.
    """
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            "TAVU-tn expects a (2, n_features) stimulus; "
            f"got shape {stim.shape}."
        )

    a = stim[0]
    b = stim[1]

    v = np.asarray(parameters["validities"], dtype=float)
    if v.size != a.size:
        raise ValueError(
            f"validities length {v.size} does not match n_features {a.size}."
        )

    gamma = float(parameters["gamma"])
    tau = float(parameters["tau"])
    tau_sd = float(parameters["tau_sd"])
    p_negative = float(parameters["p_negative"])
    sign_draw = float(parameters["sign_draw"])
    bias = float(parameters["bias"])
    lapse = float(parameters["lapse"])
    w_soft = float(parameters["soft_weight"])
    beta_soft = float(parameters["soft_beta"])
    follow_max = float(parameters["follow_max"])

    # Latent validity-sign mixture: most subjects are negative weighters.
    sign = -1.0 if sign_draw < p_negative else 1.0

    # Validity-weighted feature difference.
    d = float(np.dot(v ** gamma, a - b))

    # Analytic Gaussian threshold noise: probability that |D| crosses tau
    # when the trial-level threshold is perturbed.
    z_th = (abs(d) - tau) / tau_sd
    p_above = 0.5 * (1.0 + math.erf(z_th / math.sqrt(2.0)))
    p_above = float(np.clip(p_above, 0.0, 1.0))

    # Thresholded anti-validity target for p(A).
    if sign < 0.0:
        if d > 0.0:
            target_a = 0.0
        elif d < 0.0:
            target_a = 1.0
        else:
            target_a = bias
    else:
        if d > 0.0:
            target_a = 1.0
        elif d < 0.0:
            target_a = 0.0
        else:
            target_a = bias

    # Dominant thresholded sign rule, with a follow ceiling that keeps
    # some residual bias even after threshold crossing.
    core_threshold = (
        follow_max * (p_above * target_a + (1.0 - p_above) * bias)
        + (1.0 - follow_max) * bias
    )

    # Small validity-consistent soft leak. This is deliberately very weak
    # below |D| = 0.2 and only mildly damps extreme anti choices.
    z = beta_soft * d
    if z >= 0.0:
        soft_a = 1.0 / (1.0 + np.exp(-z))
    else:
        ez = np.exp(z)
        soft_a = ez / (1.0 + ez)

    core_a = (1.0 - w_soft) * core_threshold + w_soft * soft_a
    p_a = (1.0 - lapse) * core_a + lapse / 2.0
    p_a = float(np.clip(p_a, 0.0, 1.0))

    return np.array([p_a, 1.0 - p_a], dtype=float)

`policy(probs) -> int`:
import numpy as np


def policy(probs):
    p = np.asarray(probs, dtype=float)
    if p.sum() <= 0.0:
        p = np.ones_like(p) / len(p)
    else:
        p = p / p.sum()
    return int(np.random.choice(len(p), p=p))

`parameters`:
- gamma: [1.8, 2.2]
- tau: [0.16, 0.19]
- tau_sd: [0.02, 0.04]
- p_negative: [0.88, 0.94]
- sign_draw: [0.0, 1.0]
- bias: [0.46, 0.54]
- lapse: [0.12, 0.16]
- soft_weight: [0.00, 0.03]
- soft_beta: [0.7, 1.1]
- follow_max: [0.66, 0.74]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=-0.4323 (var=0.0402) vs this=-0.2989 (var=0.0305)
- Experiment 2: real=-0.2650 (var=0.0713) vs this=-0.1992 (var=0.0231)
- Experiment 3: real=0.3622 (var=0.0979) vs this=0.5539 (var=0.0612)
- Experiment 4: real=0.5300 (var=0.0883) vs this=0.4750 (var=0.1189)
- Experiment 5: real=-0.0300 (var=0.0191) vs this=0.0233 (var=0.0179)
- Experiment 6: real=0.0117 (var=0.0033) vs this=0.0592 (var=0.0113)
- Experiment 7: real=0.0064 (var=0.0161) vs this=0.0031 (var=0.0170)
- Experiment 8: real=0.1200 (var=0.0096) vs this=0.2039 (var=0.0121)
- Experiment 9: real=0.6008 (var=0.0611) vs this=0.4646 (var=0.0686)
- Experiment 10: real=0.0675 (var=0.0553) vs this=0.0112 (var=0.0581)
- Experiment 11: real=0.3030 (var=0.0429) vs this=0.4210 (var=0.0090)
- Experiment 12: real=0.0356 (var=0.0037) vs this=0.0889 (var=0.0111)
- Experiment 13: real=-0.5133 (var=0.1804) vs this=0.1783 (var=0.0467)
- Experiment 14: real=0.3889 (var=0.0632) vs this=0.0022 (var=0.0196)


---

### `pi_6` (overall score: 0.362)

**Description**
Validity-gated slipped-start Inverted Take-the-Best (GSS-ITTB). People order cues by stated validity and normally use the first discriminating cue, inverting its recommendation with subject-specific probability q_i. Attentional slips to later ordered cues are not driven by feature count alone; they occur mainly when the first discriminator's validity is below a threshold, and are strongly suppressed for first discriminators with validity 0.90 or higher. When a slip occurs, the later discriminating cue controls the response with a boosted inversion probability, reflecting stronger contra-indicator responding in the low-validity regime. Trials with no discriminating cue are resolved by subject-level bias, and a small lapse adds residual noise. There is no graded validity-weighted accumulation and no continuous logit over a compensatory score.

`predict(parameters, state, history) -> np.ndarray`:
import numpy as np

def predict(parameters, state, history):
    """Validity-gated slipped-start Inverted Take-the-Best (GSS-ITTB).

    Cues are ordered by stated validity. The normative first
    discriminating cue sets the subject's base inversion probability
    q_norm. Attentional slips to later ordered cues are gated by the
    validity of that first discriminator: slips are allowed and
    strengthened when validity is below gate_low, ramp down between
    gate_low and 0.90, and are switched off at 0.90 or above. Slipped
    responses use a boosted inversion strength q_slip. If no cue
    discriminates, a subject-level bias is used. No graded cue
    accumulation enters the model.
    """
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError(
            "GSS-ITTB expects a (2, n_features) stimulus; "
            f"got shape {stim.shape}."
        )

    a = stim[0]
    b = stim[1]

    v = np.asarray(parameters["validities"], dtype=float)
    if v.size != a.size:
        raise ValueError(
            f"validities length {v.size} does not match n_features {a.size}."
        )

    n = int(a.size)

    q_lo = float(parameters["q_lo"])
    q_mid = float(parameters["q_mid"])
    q_90 = float(parameters["q_90"])
    q_92 = float(parameters["q_92"])
    q_hi = float(parameters["q_hi"])
    q_floor = float(parameters["q_floor"])
    bias = float(parameters["bias"])
    epsilon = float(parameters["epsilon"])
    late2_base = float(parameters["late2_base"])
    late2_slope = float(parameters["late2_slope"])
    late3_base = float(parameters["late3_base"])
    late3_slope = float(parameters["late3_slope"])
    gate_low = float(parameters["gate_low"])
    q_low_boost = float(parameters["q_low_boost"])
    max_slip = float(parameters["max_slip"])

    def q_of(vv):
        vv = float(vv)
        if vv > 0.97:
            return float(np.clip(q_floor, 0.0, 1.0))
        return float(np.interp(
            vv,
            np.array([0.50, 0.80, 0.90, 0.92, 0.95], dtype=float),
            np.array([q_lo, q_mid, q_90, q_92, q_hi], dtype=float),
        ))

    cue_order = np.argsort(-v, kind="stable")

    def first_disc(start_idx):
        for r in range(start_idx, n):
            j = int(cue_order[r])
            if a[j] != b[j]:
                return j
        return -1

    j0 = first_disc(0)

    if j0 < 0:
        # No discriminating cue anywhere: subject-level bias.
        p_core = bias
    else:
        # Base inversion strength is calibrated by the normative first
        # discriminating cue.
        q_norm = q_of(v[j0])

        # Feature-count pressure toward late search.
        extra = max(0.0, float(n - 5))
        late2 = float(np.clip(late2_base + late2_slope * extra, 0.0, 0.90))
        late3 = float(np.clip(late3_base + late3_slope * extra, 0.0, 0.60))

        # Validity gate on slip: full slip below gate_low, zero slip at
        # validity 0.90 or higher, linear ramp between.
        vj0 = float(v[j0])
        if vj0 < gate_low:
            gate = 1.0
        elif vj0 >= 0.90:
            gate = 0.0
        else:
            gate = (0.90 - vj0) / (0.90 - gate_low)
        gate = float(np.clip(gate, 0.0, 1.0))

        late2 *= gate
        late3 *= gate

        if late2 + late3 > max_slip:
            scale = max_slip / (late2 + late3)
            late2 *= scale
            late3 *= scale

        p0 = 1.0 - late2 - late3

        # Slipped-to cues are inverted more strongly in the gated regime.
        q_slip = float(np.clip(q_norm + q_low_boost * gate, 0.0, 1.0))

        def direction_prob(start_idx, q_val):
            j = first_disc(start_idx)
            if j < 0:
                return bias
            if a[j] > b[j]:
                # Effective cue favors A, so inverted tendency chooses B.
                return 1.0 - q_val
            # Effective cue favors B, so inverted tendency chooses A.
            return q_val

        p_core = (
            p0 * direction_prob(0, q_norm)
            + late2 * direction_prob(2, q_slip)
            + late3 * direction_prob(3, q_slip)
        )

    p_a_core = float(np.clip(p_core, 0.0, 1.0))

    # Uniform lapse over the two options.
    p_a = (1.0 - epsilon) * p_a_core + epsilon / 2.0
    p_a = float(np.clip(p_a, 0.0, 1.0))

    return np.array([p_a, 1.0 - p_a], dtype=float)


`policy(probs) -> int`:
import numpy as np

def policy(probs):
    p = np.asarray(probs, dtype=float)
    if p.sum() <= 0.0:
        p = np.ones_like(p) / len(p)
    else:
        p = p / p.sum()
    return int(np.random.choice(len(p), p=p))


`parameters`:
- q_lo: [0.20, 0.40]
- q_mid: [0.55, 0.68]
- q_90: [0.66, 0.82]
- q_92: [0.48, 0.62]
- q_hi: [0.70, 0.86]
- q_floor: [0.45, 0.65]
- bias: [0.30, 0.70]
- epsilon: [0.02, 0.08]
- late2_base: [0.02, 0.08]
- late2_slope: [0.80, 1.10]
- late3_base: [0.02, 0.06]
- late3_slope: [0.10, 0.25]
- gate_low: [0.84, 0.88]
- q_low_boost: [0.10, 0.25]
- max_slip: [0.93, 0.98]
- validities: validities

**Per-experiment fit (real vs this theory's metric value):**
- Experiment 1: real=-0.4323 (var=0.0402) vs this=-0.0094 (var=0.0045)
- Experiment 2: real=-0.2650 (var=0.0713) vs this=-0.2996 (var=0.0120)
- Experiment 3: real=0.3622 (var=0.0979) vs this=0.4500 (var=0.0174)
- Experiment 4: real=0.5300 (var=0.0883) vs this=0.5700 (var=0.0173)
- Experiment 5: real=-0.0300 (var=0.0191) vs this=0.0075 (var=0.0255)
- Experiment 6: real=0.0117 (var=0.0033) vs this=-0.0083 (var=0.0131)
- Experiment 7: real=0.0064 (var=0.0161) vs this=-0.0130 (var=0.0249)
- Experiment 8: real=0.1200 (var=0.0096) vs this=0.0919 (var=0.0049)
- Experiment 9: real=0.6008 (var=0.0611) vs this=0.0171 (var=0.0067)
- Experiment 10: real=0.0675 (var=0.0553) vs this=0.3900 (var=0.0990)
- Experiment 11: real=0.3030 (var=0.0429) vs this=0.2820 (var=0.0122)
- Experiment 12: real=0.0356 (var=0.0037) vs this=0.0667 (var=0.0098)
- Experiment 13: real=-0.5133 (var=0.1804) vs this=-0.4200 (var=0.1072)
- Experiment 14: real=0.3889 (var=0.0632) vs this=0.0500 (var=0.0899)


## EXPERIMENTAL RESULTS
### Experiment 1
**Design**
  A=[1, 1, 1, 1, 1, 0]  B=[0, 0, 0, 0, 0, 1]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 1, 1, 1]
  A=[0, 1, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[0, 1, 1, 1, 0, 0]  B=[1, 0, 0, 0, 1, 1]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 1, 1, 1]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 1, 1, 1, 1]

**Metric**
```python
def metric(data):
    import numpy as np
    min_class = 12
    groups = {0: [], 1: []}
    for _, row in data.iterrows():
        a = np.asarray(row['option_a_ratings'], dtype=int)
        b = np.asarray(row['option_b_ratings'], dtype=int)
        if a[0] > b[0]:
            grp = 0
        elif b[0] > a[0]:
            grp = 1
        else:
            continue
        tally = int(np.sum(a > b) - np.sum(b > a))
        chose_a = 1.0 if int(row['response']) == 0 else 0.0
        groups[grp].append((tally, chose_a))
    parts = []
    for grp in (0, 1):
        vals = groups[grp]
        if not vals:
            parts.append(0.0)
            continue
        d_a = [d for d, y in vals if y == 1.0]
        d_b = [d for d, y in vals if y == 0.0]
        if len(d_a) < min_class or len(d_b) < min_class:
            parts.append(0.0)
        else:
            parts.append((np.mean(d_a) - np.mean(d_b)) / 6.0)
    return float(np.mean(parts))
```

**Observed (real) value:** -0.4323 (var=0.0402)
**Other theories' values on this metric (for reference):**
- pi_1: 0.0157 (var=0.0016)
- pi_2: 0.4517 (var=0.0090)
- pi_3: -0.5184 (var=0.0087)
- pi_4: -0.3839 (var=0.0765)
- pi_5: -0.2852 (var=0.0363)
- pi_6: -0.0094 (var=0.0045)
- pi_7: -0.3210 (var=0.0633)
- pi_7_1: -0.2989 (var=0.0305)

### Experiment 2
**Design**
  A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 1]
  A=[0, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 1, 1, 0]
  A=[1, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 1, 0]
  A=[0, 0, 1, 1, 0]  B=[0, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 1]  B=[1, 0, 1, 0, 1]
  A=[1, 1, 0, 0, 1]  B=[1, 0, 1, 1, 1]
  A=[1, 0, 1, 0, 1]  B=[0, 1, 1, 0, 1]
  A=[1, 0, 1, 0, 0]  B=[1, 1, 0, 0, 0]
  A=[0, 1, 0, 1, 1]  B=[0, 0, 1, 1, 1]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 1, 1, 0]

**Metric**
```python
def metric(data):
    import numpy as np
    validities = np.array([0.9, 0.8, 0.65, 0.55, 0.5])
    cue_order = np.argsort(-validities, kind='stable')
    a_when_ttb_a = []
    a_when_ttb_b = []
    for _, row in data.iterrows():
        a = np.asarray(row['option_a_ratings'], dtype=float)
        b = np.asarray(row['option_b_ratings'], dtype=float)
        ttb_winner = -1
        for j in cue_order:
            if a[j] > b[j]:
                ttb_winner = 0
                break
            if b[j] > a[j]:
                ttb_winner = 1
                break
        if ttb_winner == -1:
            continue
        chose_a = 1 if int(row['response']) == 0 else 0
        if ttb_winner == 0:
            a_when_ttb_a.append(chose_a)
        else:
            a_when_ttb_b.append(chose_a)
    if not a_when_ttb_a or not a_when_ttb_b:
        return 0.0
    return float(np.mean(a_when_ttb_a) - np.mean(a_when_ttb_b))
```

**Observed (real) value:** -0.2650 (var=0.0713)
**Other theories' values on this metric (for reference):**
- pi_2: -0.0083 (var=0.0072)
- pi_1: 0.6883 (var=0.0485)
- pi_3: -0.2804 (var=0.0079)
- pi_4: -0.3037 (var=0.0165)
- pi_5: -0.2133 (var=0.0171)
- pi_6: -0.2996 (var=0.0120)
- pi_7: -0.2604 (var=0.0412)
- pi_7_1: -0.1992 (var=0.0231)

### Experiment 3
**Design**
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 0]  B=[1, 1, 1, 0, 0, 0]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 1, 1, 1, 0, 0]

**Metric**
```python
def metric(data):
    import numpy as np
    import pandas as pd

    df = data.copy()
    df["pair_key"] = df.apply(
        lambda r: (tuple(r["option_a_ratings"]), tuple(r["option_b_ratings"])),
        axis=1,
    )

    nwa_negative_pairs = [
        ((1, 1, 1, 0, 0, 0), (0, 0, 0, 1, 1, 1)),
        ((1, 1, 1, 0, 0, 0), (0, 0, 0, 1, 1, 0)),
        ((1, 1, 0, 0, 0, 0), (0, 0, 0, 1, 1, 1)),
    ]
    nwa_positive_pairs = [
        ((0, 0, 0, 1, 1, 1), (1, 1, 1, 0, 0, 0)),
        ((0, 0, 0, 1, 1, 1), (1, 1, 0, 0, 0, 0)),
        ((0, 0, 0, 1, 1, 0), (1, 1, 1, 0, 0, 0)),
    ]

    def p_a_for_key(d, key):
        mask = d["pair_key"] == key
        return 1.0 - float(d.loc[mask, "response"].mean())

    def subject_score(d):
        neg = [p_a_for_key(d, k) for k in nwa_negative_pairs]
        pos = [p_a_for_key(d, k) for k in nwa_positive_pairs]
        return sum([pos[i] - neg[i] for i in range(3)]) / 3.0

    scores = df.groupby("subject_id", sort=False).apply(subject_score)
    return float(scores.mean())

```

**Observed (real) value:** 0.3622 (var=0.0979)
**Other theories' values on this metric (for reference):**
- pi_3: 0.8928 (var=0.0032)
- pi_2: 0.0017 (var=0.0075)
- pi_1: -0.7161 (var=0.0463)
- pi_4: 0.5850 (var=0.1060)
- pi_5: 0.5467 (var=0.1673)
- pi_6: 0.4500 (var=0.0174)
- pi_7: 0.5911 (var=0.1735)
- pi_7_1: 0.5539 (var=0.0612)

### Experiment 4
**Design**
  A=[1, 1, 0, 0]  B=[0, 0, 1, 1]
  A=[1, 0, 1, 0]  B=[0, 1, 0, 1]
  A=[1, 0, 0, 1]  B=[0, 1, 1, 0]
  A=[0, 1, 1, 0]  B=[1, 0, 0, 1]
  A=[0, 1, 0, 1]  B=[1, 0, 1, 0]
  A=[0, 0, 1, 1]  B=[1, 1, 0, 0]
  A=[0, 1, 1, 1]  B=[1, 0, 0, 0]
  A=[1, 0, 0, 0]  B=[0, 1, 1, 1]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    diffs = [tuple(int(x) - int(y) for x, y in zip(a, b)) for a, b in zip(data['option_a_ratings'], data['option_b_ratings'])]
    choose_a = (data['response'].to_numpy(dtype=float) == 0).astype(float)
    high_keys = {(-1, -1, 1, 1), (-1, 1, -1, 1)}
    low_keys = {(1, 1, -1, -1), (1, -1, 1, -1)}
    high_mask = np.array([d in high_keys for d in diffs], dtype=bool)
    low_mask = np.array([d in low_keys for d in diffs], dtype=bool)
    if high_mask.sum() == 0 or low_mask.sum() == 0:
        return 0.0
    return float(choose_a[high_mask].mean() - choose_a[low_mask].mean())
```

**Observed (real) value:** 0.5300 (var=0.0883)
**Other theories' values on this metric (for reference):**
- pi_2: 0.0025 (var=0.0212)
- pi_3: 0.6125 (var=0.0127)
- pi_1: -0.6867 (var=0.0422)
- pi_4: 0.5467 (var=0.0492)
- pi_5: 0.5175 (var=0.0843)
- pi_6: 0.5700 (var=0.0173)
- pi_7: 0.5675 (var=0.2300)
- pi_7_1: 0.4750 (var=0.1189)

### Experiment 5
**Design**
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[1, 0, 1, 1, 1, 1]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 1, 1, 1, 1]

**Metric**
```python
import numpy as np
import pandas as pd

def metric(data: pd.DataFrame) -> float:
    pair_specs = {
        'cp': ((1, 1, 1, 0, 0, 0), (0, 0, 0, 1, 1, 1)),
        'ap': ((1, 0, 1, 1, 1, 1), (0, 1, 0, 0, 0, 0)),
        'cn': ((0, 0, 0, 1, 1, 1), (1, 1, 1, 0, 0, 0)),
        'an': ((0, 1, 0, 0, 0, 0), (1, 0, 1, 1, 1, 1)),
    }
    lookup = {v: k for k, v in pair_specs.items()}

    df = data.copy()
    df['_pair'] = [
        lookup.get((tuple(a), tuple(b)), 'other')
        for a, b in zip(df['option_a_ratings'], df['option_b_ratings'])
    ]
    df['_chose_a'] = (df['response'] == 0).astype(float)

    subject_effects = []
    for _, sub in df.groupby('subject_id'):
        means = sub.groupby('_pair')['_chose_a'].mean()
        if not {'cp', 'ap', 'cn', 'an'}.issubset(means.index):
            continue
        cp = means['cp']
        ap = means['ap']
        cn = means['cn']
        an = means['an']
        effect = (
            (abs(ap - 0.5) - abs(cp - 0.5))
            + (abs(an - 0.5) - abs(cn - 0.5))
        )
        subject_effects.append(effect)

    if not subject_effects:
        return float('nan')
    effects = np.asarray(subject_effects, dtype=float)
    if np.any(np.isnan(effects)):
        return float('nan')
    return float(effects.mean())
```

**Observed (real) value:** -0.0300 (var=0.0191)
**Other theories' values on this metric (for reference):**
- pi_3: -0.0017 (var=0.0039)
- pi_4: 0.6350 (var=0.0201)
- pi_1: -0.0033 (var=0.0180)
- pi_2: 0.6083 (var=0.0361)
- pi_5: 0.0050 (var=0.0269)
- pi_6: 0.0075 (var=0.0255)
- pi_7: -0.0325 (var=0.0234)
- pi_7_1: 0.0233 (var=0.0179)

### Experiment 6
**Design**
  A=[1, 0, 1, 0, 0, 1, 0]  B=[0, 1, 0, 1, 1, 0, 0]
  A=[1, 0, 1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0, 1, 0]
  A=[1, 1, 0, 0, 0, 1, 0]  B=[0, 0, 1, 1, 1, 0, 0]
  A=[1, 1, 0, 0, 1, 0, 0]  B=[0, 0, 1, 1, 0, 1, 0]
  A=[0, 1, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 1, 1, 0]
  A=[1, 0, 1, 1, 0, 0, 0]  B=[0, 1, 0, 0, 1, 1, 0]
  A=[1, 1, 0, 1, 0, 0, 0]  B=[0, 0, 1, 0, 1, 1, 0]
  A=[1, 1, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1, 0]

**Metric**
```python
import numpy as np

def metric(data):
    v = np.array([0.95, 0.9, 0.85, 0.8, 0.6, 0.55, 0.5], dtype=float)

    a = np.asarray(data['option_a_ratings'].tolist(), dtype=float)
    b = np.asarray(data['option_b_ratings'].tolist(), dtype=float)
    z = (a - b).dot(v ** 2)

    resp = np.asarray(data['response'], dtype=float)

    low_mask = z < 0.5
    high_mask = z > 0.9

    lows = resp[low_mask]
    highs = resp[high_mask]

    if lows.size == 0 or highs.size == 0:
        return float('nan')

    p_a_low = float(np.mean(lows == 0))
    p_a_high = float(np.mean(highs == 0))

    return float(p_a_low - p_a_high)

```

**Observed (real) value:** 0.0117 (var=0.0033)
**Other theories' values on this metric (for reference):**
- pi_4: -0.0158 (var=0.0128)
- pi_3: 0.2812 (var=0.0041)
- pi_1: -0.0062 (var=0.0073)
- pi_2: 0.0254 (var=0.0198)
- pi_5: 0.0663 (var=0.0100)
- pi_6: -0.0083 (var=0.0131)
- pi_7: -0.0021 (var=0.0067)
- pi_7_1: 0.0592 (var=0.0113)

### Experiment 7
**Design**
  A=[1, 0, 1, 0, 1]  B=[0, 1, 0, 1, 0]
  A=[1, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[1, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]
  A=[1, 1, 0, 1, 0]  B=[0, 0, 1, 0, 1]
  A=[1, 0, 1, 1, 1]  B=[0, 1, 0, 0, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[1, 1, 0, 1, 1]  B=[0, 0, 1, 0, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 1]
  A=[0, 1, 0, 0, 1]  B=[1, 0, 1, 1, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 0, 1, 0, 1]  B=[1, 1, 0, 1, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 1, 1, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[0, 0, 1, 0, 0]  B=[1, 1, 0, 1, 1]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    validities = np.array([0.92, 0.84, 0.74, 0.62, 0.52], dtype=float)
    weights = validities ** 2.25

    a_rows = [np.asarray(r, dtype=float) for r in data['option_a_ratings']]
    b_rows = [np.asarray(r, dtype=float) for r in data['option_b_ratings']]
    if len(a_rows) == 0:
        return 0.0

    a = np.vstack(a_rows)
    b = np.vstack(b_rows)
    d = (a - b) @ weights

    resp = data['response'].to_numpy(dtype=float)
    sign_consistent = np.zeros(len(data), dtype=float)
    sign_consistent[(d > 0.0) & (resp == 1.0)] = 1.0
    sign_consistent[(d < 0.0) & (resp == 0.0)] = 1.0

    x = np.abs(d)
    xc = x - x.mean()
    denom = np.sum(xc * xc)
    if denom < 1e-12:
        return 0.0
    return float(np.sum(xc * sign_consistent) / denom)

```

**Observed (real) value:** 0.0064 (var=0.0161)
**Other theories' values on this metric (for reference):**
- pi_3: 0.1683 (var=0.0061)
- pi_5: 0.0393 (var=0.0171)
- pi_1: -0.0904 (var=0.0098)
- pi_2: 0.0118 (var=0.0112)
- pi_4: 0.0529 (var=0.0066)
- pi_6: -0.0130 (var=0.0249)
- pi_7: -0.0377 (var=0.0119)
- pi_7_1: 0.0031 (var=0.0170)

### Experiment 8
**Design**
  A=[0, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[1, 0, 1, 0, 0]  B=[0, 1, 0, 1, 0]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 1]
  A=[1, 1, 0, 0, 0]  B=[0, 0, 1, 1, 0]
  A=[1, 1, 0, 0, 1]  B=[0, 0, 1, 1, 0]
  A=[1, 1, 1, 0, 0]  B=[0, 0, 0, 1, 1]
  A=[0, 0, 1, 1, 0]  B=[0, 1, 0, 0, 1]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 1]  B=[1, 0, 0, 1, 0]
  A=[0, 1, 0, 1, 0]  B=[1, 0, 1, 0, 0]
  A=[0, 0, 1, 1, 1]  B=[1, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 0]
  A=[0, 0, 1, 1, 0]  B=[1, 1, 0, 0, 1]
  A=[0, 0, 0, 1, 1]  B=[1, 1, 1, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np

    validities = np.array([0.95, 0.9, 0.8, 0.6, 0.5], dtype=float)
    weights = validities ** 2.25

    subject_contrasts = []
    for _, subj in data.groupby('subject_id'):
        cons = []
        high_mask = []
        low_mask = []

        for _, row in subj.iterrows():
            a = np.asarray(row['option_a_ratings'], dtype=float)
            b = np.asarray(row['option_b_ratings'], dtype=float)
            d = float(np.dot(weights, a - b))
            ad = abs(d)

            # Negative-validity prediction: choose B when A has larger
            # validity-weighted advantage, otherwise choose A.
            pred_neg = 1 if d > 0 else 0
            cons.append(1.0 if int(row['response']) == pred_neg else 0.0)
            high_mask.append(ad >= 0.90)
            low_mask.append(ad <= 0.25)

        cons = np.array(cons)
        high_mask = np.array(high_mask, dtype=bool)
        low_mask = np.array(low_mask, dtype=bool)

        if high_mask.sum() == 0 or low_mask.sum() == 0:
            subject_contrasts.append(0.0)
            continue

        raw_contrast = float(cons[high_mask].mean() - cons[low_mask].mean())
        # Absolute value aligns negative-sign and positive-sign subjects.
        subject_contrasts.append(abs(raw_contrast))

    if not subject_contrasts:
        return 0.0
    return float(np.mean(subject_contrasts))
```

**Observed (real) value:** 0.1200 (var=0.0096)
**Other theories' values on this metric (for reference):**
- pi_5: 0.1742 (var=0.0110)
- pi_3: 0.3681 (var=0.0125)
- pi_1: 0.0822 (var=0.0037)
- pi_2: 0.3414 (var=0.0202)
- pi_4: 0.3106 (var=0.0090)
- pi_6: 0.0919 (var=0.0049)
- pi_7: 0.1086 (var=0.0084)
- pi_7_1: 0.2039 (var=0.0121)

### Experiment 9
**Design**
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 0, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 0]
  A=[1, 0, 0, 0, 0]  B=[0, 1, 1, 1, 1]
  A=[0, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 1, 0, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 0]  B=[1, 0, 0, 0, 0]
  A=[0, 1, 1, 1, 1]  B=[1, 0, 0, 0, 0]

**Metric**
```python
def metric(data: pd.DataFrame) -> float:
    import numpy as np

    validities = np.array([0.9, 0.8, 0.7, 0.6, 0.79], dtype=float)
    gamma = 2.0
    weights = validities ** gamma

    def d_sign(row):
        a = np.asarray(row['option_a_ratings'], dtype=float)
        b = np.asarray(row['option_b_ratings'], dtype=float)
        d = float(np.dot(weights, a - b))
        if d > 0.0:
            return 1
        if d < 0.0:
            return -1
        return 0

    signs = data.apply(d_sign, axis=1)
    p_a = 1.0 - data['response'].astype(float)

    neg_mean = p_a[signs == -1].mean()
    pos_mean = p_a[signs == 1].mean()

    return float(neg_mean - pos_mean)
```

**Observed (real) value:** 0.6008 (var=0.0611)
**Other theories' values on this metric (for reference):**
- pi_6: 0.0171 (var=0.0067)
- pi_5: 0.4529 (var=0.1083)
- pi_1: -0.0108 (var=0.0045)
- pi_2: -0.4979 (var=0.0189)
- pi_3: 0.5787 (var=0.0079)
- pi_4: 0.6096 (var=0.1186)
- pi_7: 0.5908 (var=0.1650)
- pi_7_1: 0.4646 (var=0.0686)

### Experiment 10
**Design**
  A=[1, 1, 1, 1, 1]  B=[0, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 1]  B=[1, 0, 1, 1, 1]
  A=[1, 1, 1, 1, 1]  B=[1, 1, 0, 1, 1]
  A=[1, 1, 1, 1, 1]  B=[1, 1, 1, 0, 0]
  A=[1, 1, 1, 1, 1]  B=[1, 1, 1, 1, 0]
  A=[1, 1, 1, 1, 0]  B=[1, 1, 1, 0, 1]
  A=[0, 1, 1, 1, 1]  B=[1, 1, 1, 1, 1]
  A=[1, 0, 1, 1, 1]  B=[1, 1, 1, 1, 1]
  A=[1, 1, 0, 1, 1]  B=[1, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 0]  B=[1, 1, 1, 1, 1]
  A=[1, 1, 1, 1, 0]  B=[1, 1, 1, 1, 1]
  A=[1, 1, 1, 0, 1]  B=[1, 1, 1, 1, 0]

**Metric**
```python
import numpy as np
import pandas as pd

def metric(data: pd.DataFrame) -> float:
    a_key = data["option_a_ratings"].apply(tuple)
    b_key = data["option_b_ratings"].apply(tuple)
    ones = (1, 1, 1, 1, 1)

    def anti_cue_rate(k):
        b_target = list(ones)
        b_target[k] = 0
        b_target = tuple(b_target)

        a_target = list(ones)
        a_target[k] = 0
        a_target = tuple(a_target)

        mask_b = (a_key == ones) & (b_key == b_target)
        mask_a = (a_key == a_target) & (b_key == ones)

        anti = np.concatenate([
            (data.loc[mask_b, "response"].to_numpy() == 1).astype(float),
            (data.loc[mask_a, "response"].to_numpy() == 0).astype(float),
        ])

        if anti.size == 0:
            return 0.5
        return float(anti.mean())

    r95 = anti_cue_rate(0)
    r92 = anti_cue_rate(1)
    r90 = anti_cue_rate(2)

    return r95 - 2.0 * r92 + r90

```

**Observed (real) value:** 0.0675 (var=0.0553)
**Other theories' values on this metric (for reference):**
- pi_5: -0.0025 (var=0.0475)
- pi_6: 0.3900 (var=0.0990)
- pi_1: 0.0038 (var=0.0376)
- pi_2: -0.0063 (var=0.0516)
- pi_3: 0.0075 (var=0.0206)
- pi_4: -0.0288 (var=0.0177)
- pi_7: -0.0012 (var=0.0416)
- pi_7_1: 0.0112 (var=0.0581)

### Experiment 11
**Design**
  A=[1, 0, 0, 1, 0, 0]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 1, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 0, 0, 1]
  A=[1, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 1]
  A=[1, 1, 1, 0, 0, 0]  B=[0, 0, 0, 1, 1, 1]
  A=[0, 1, 1, 0, 0, 0]  B=[1, 0, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0, 1]  B=[0, 1, 1, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 0, 0, 1, 0]
  A=[0, 1, 0, 0, 0, 1]  B=[1, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 1]  B=[1, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 1, 1]  B=[1, 1, 1, 0, 0, 0]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    pos_pairs = {
        ((0, 1, 1, 0, 0, 0), (1, 0, 0, 0, 0, 1)),
        ((1, 0, 0, 0, 1, 0), (0, 1, 0, 0, 0, 1)),
        ((1, 0, 1, 0, 0, 0), (0, 1, 0, 0, 0, 1)),
        ((1, 1, 0, 0, 0, 0), (0, 0, 1, 0, 0, 1)),
        ((1, 1, 1, 0, 0, 0), (0, 0, 0, 1, 1, 1)),
    }
    neg_pairs = {
        ((1, 0, 0, 0, 0, 1), (0, 1, 1, 0, 0, 0)),
        ((0, 1, 0, 0, 0, 1), (1, 0, 0, 0, 1, 0)),
        ((0, 1, 0, 0, 0, 1), (1, 0, 1, 0, 0, 0)),
        ((0, 0, 1, 0, 0, 1), (1, 1, 0, 0, 0, 0)),
        ((0, 0, 0, 1, 1, 1), (1, 1, 1, 0, 0, 0)),
    }

    def pair_key(r):
        return (tuple(r['option_a_ratings']), tuple(r['option_b_ratings']))

    df = data.copy()
    df['_pair'] = df.apply(pair_key, axis=1)

    def subject_score(g):
        pos = g.loc[g['_pair'].isin(pos_pairs), 'response'].eq(0).mean()
        neg = g.loc[g['_pair'].isin(neg_pairs), 'response'].eq(0).mean()
        if pd.isna(pos) or pd.isna(neg):
            return np.nan
        return float(abs(neg - pos))

    scores = df.groupby('subject_id', sort=False).apply(subject_score).dropna()
    if scores.empty:
        return 0.0
    return float(scores.mean())

```

**Observed (real) value:** 0.3030 (var=0.0429)
**Other theories' values on this metric (for reference):**
- pi_7: 0.6370 (var=0.0065)
- pi_5: 0.4985 (var=0.0248)
- pi_1: 0.4260 (var=0.0186)
- pi_2: 0.0945 (var=0.0049)
- pi_3: 0.4940 (var=0.0078)
- pi_4: 0.4570 (var=0.0075)
- pi_6: 0.2820 (var=0.0122)
- pi_7_1: 0.4210 (var=0.0090)

### Experiment 12
**Design**
  A=[1, 0, 1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 0, 0, 1]  B=[0, 1, 0, 1, 0, 1, 1, 0]
  A=[1, 0, 1, 0, 0, 1, 1, 0]  B=[0, 1, 0, 1, 1, 0, 0, 1]
  A=[1, 0, 1, 0, 0, 0, 1, 0]  B=[0, 1, 0, 1, 0, 0, 0, 1]
  A=[1, 0, 1, 0, 0, 0, 0, 1]  B=[0, 1, 0, 1, 0, 0, 1, 0]
  A=[1, 0, 1, 0, 1, 0, 0, 0]  B=[0, 1, 0, 1, 0, 1, 0, 0]
  A=[1, 0, 1, 0, 0, 1, 0, 0]  B=[0, 1, 0, 1, 1, 0, 0, 0]
  A=[1, 0, 1, 0, 1, 0, 1, 0]  B=[0, 1, 0, 1, 0, 1, 0, 1]
  A=[1, 0, 1, 0, 0, 1, 0, 1]  B=[0, 1, 0, 1, 1, 0, 1, 0]
  A=[1, 0, 1, 0, 0, 0, 0, 1]  B=[0, 1, 0, 1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 0, 0, 1]
  A=[1, 0, 1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 1, 0, 1, 0, 0, 0, 0]
  A=[1, 0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0, 0, 0]  B=[1, 0, 0, 1, 0, 0, 0, 0]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    v = np.array([0.92, 0.92, 0.65, 0.65, 0.7, 0.6, 0.5, 0.5], dtype=float)
    df = data.copy()

    def _d(row):
        a = np.asarray(row['option_a_ratings'], dtype=float)
        b = np.asarray(row['option_b_ratings'], dtype=float)
        return float(np.sum((v ** 2.0) * (a - b)))

    df['__d'] = df.apply(_d, axis=1)
    df['__pa'] = 1.0 - df['response'].astype(float)

    out = []
    for _, sub in df.groupby('subject_id', sort=False):
        orient = sub[sub['__d'].abs() >= 0.16]
        small = sub[(sub['__d'].abs() > 0.03) & (sub['__d'].abs() < 0.16)]
        if len(orient) == 0 or len(small) == 0:
            continue

        p_pos_orient = orient.loc[orient['__d'] > 0, '__pa'].mean()
        p_neg_orient = orient.loc[orient['__d'] < 0, '__pa'].mean()
        if pd.isna(p_pos_orient) or pd.isna(p_neg_orient):
            continue

        p_pos_small = small.loc[small['__d'] > 0, '__pa'].mean()
        p_neg_small = small.loc[small['__d'] < 0, '__pa'].mean()
        if pd.isna(p_pos_small) or pd.isna(p_neg_small):
            continue

        if p_neg_orient >= p_pos_orient:
            step = p_neg_small - p_pos_small
        else:
            step = p_pos_small - p_neg_small

        out.append(float(np.clip(step, 0.0, 1.0)))

    if not out:
        return float('nan')
    return float(np.mean(out))
```

**Observed (real) value:** 0.0356 (var=0.0037)
**Other theories' values on this metric (for reference):**
- pi_5: 0.3367 (var=0.0255)
- pi_7: 0.5667 (var=0.0157)
- pi_1: 0.0500 (var=0.0053)
- pi_2: 0.0500 (var=0.0074)
- pi_3: 0.1756 (var=0.0288)
- pi_4: 0.2911 (var=0.0172)
- pi_6: 0.0667 (var=0.0098)
- pi_7_1: 0.0889 (var=0.0111)

### Experiment 13
**Design**
  A=[1, 0, 0, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 1, 0, 0]
  A=[1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 1, 1]
  A=[0, 1, 0, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 1, 0, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1]  B=[0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 1, 0, 0]  B=[1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 1, 1]  B=[1, 0, 0, 0, 0, 0]

**Metric**
```python
import numpy as np
import pandas as pd


def metric(data: pd.DataFrame) -> float:
    validities = np.array([0.96, 0.94, 0.9, 0.8, 0.6, 0.6], dtype=float)

    def subject_contrast(group: pd.DataFrame) -> float:
        rows = []
        for _, row in group.iterrows():
            a = tuple(int(x) for x in row['option_a_ratings'])
            b = tuple(int(x) for x in row['option_b_ratings'])
            a_arr = np.array(a, dtype=float)
            b_arr = np.array(b, dtype=float)
            d_ref = float(np.dot(validities ** 2.0, a_arr - b_arr))
            pair = tuple(sorted((a, b)))
            orient = 0 if a < b else 1
            rows.append((pair, orient, abs(d_ref), 1.0 - float(row['response'])))

        recs = pd.DataFrame(rows, columns=['pair', 'orient', 'd_ref_abs', 'p_a'])
        means = recs.groupby(['pair', 'orient'])['p_a'].mean().reset_index()

        def gap_fn(s):
            vals = list(s)
            if len(vals) < 2:
                return float('nan')
            return abs(vals[0] - vals[1])

        gaps = means.groupby('pair')['p_a'].apply(gap_fn)
        d_ref = recs.groupby('pair')['d_ref_abs'].first()

        low = gaps[d_ref < 0.15]
        high = gaps[d_ref > 0.22]
        if low.empty or high.empty:
            return float('nan')
        return float(high.mean() - 2.0 * low.mean())

    per_subject = data.groupby('subject_id').apply(subject_contrast)
    return float(per_subject.mean())

```

**Observed (real) value:** -0.5133 (var=0.1804)
**Other theories' values on this metric (for reference):**
- pi_7_1: 0.1783 (var=0.0467)
- pi_5: -0.1583 (var=0.0665)
- pi_1: -0.7567 (var=0.0822)
- pi_2: -0.5517 (var=0.0341)
- pi_3: -0.1083 (var=0.0701)
- pi_4: -0.0517 (var=0.0622)
- pi_6: -0.4200 (var=0.1072)
- pi_7: -0.1233 (var=0.0845)

### Experiment 14
**Design**
  A=[0, 0, 0, 0, 0, 0, 0, 1, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 1, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 1, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 1, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 1, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 1, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 1, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1]
  A=[1, 0, 0, 0, 0, 0, 0, 0, 0]  B=[0, 0, 0, 0, 0, 0, 0, 0, 1]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 0, 0, 0, 1, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 0, 0, 1, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 0, 1, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 0, 1, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 0, 1, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 0, 1, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1]  B=[0, 1, 0, 0, 0, 0, 0, 0, 0]
  A=[0, 0, 0, 0, 0, 0, 0, 0, 1]  B=[1, 0, 0, 0, 0, 0, 0, 0, 0]

**Metric**
```python
import numpy as np
import pandas as pd

_V = np.array([0.95, 0.87, 0.75, 0.68, 0.65, 0.62, 0.61, 0.60, 0.60], dtype=float)
_GAMMA = 2.0
_LOW_LO = 0.015
_LOW_HI = 0.15
_HIGH_CUT = 0.17

def metric(data):
    if data.empty:
        return 0.0

    values = []
    for _, sub in data.groupby('subject_id', sort=False):
        a = np.array(sub['option_a_ratings'].tolist(), dtype=float)
        b = np.array(sub['option_b_ratings'].tolist(), dtype=float)
        d = (a - b).dot(_V ** _GAMMA)

        pa = (sub['response'].to_numpy(dtype=float) == 0.0).astype(float)

        pos_low = (d > _LOW_LO) & (d < _LOW_HI)
        neg_low = (d < -_LOW_LO) & (d > -_LOW_HI)
        if pos_low.sum() == 0 or neg_low.sum() == 0:
            continue

        contrast = float(pa[neg_low].mean() - pa[pos_low].mean())

        high_pos = pa[d > _HIGH_CUT]
        high_neg = pa[d < -_HIGH_CUT]
        if high_pos.size > 0 and high_neg.size > 0:
            hp = float(high_pos.mean())
            hn = float(high_neg.mean())
            if hp - hn > 0.0:
                contrast = -contrast

        values.append(contrast)

    if not values:
        return 0.0
    return float(np.mean(values))
```

**Observed (real) value:** 0.3889 (var=0.0632)
**Other theories' values on this metric (for reference):**
- pi_5: 0.2444 (var=0.0354)
- pi_7_1: 0.0022 (var=0.0196)
- pi_1: 0.6922 (var=0.0530)
- pi_2: -0.0156 (var=0.0177)
- pi_3: 0.1011 (var=0.0282)
- pi_4: 0.1178 (var=0.0185)
- pi_6: 0.0500 (var=0.0899)
- pi_7: 0.4067 (var=0.0180)


## IMPLEMENTATION GUARDRAILS
- The parameters should be within the specified ranges.
- The model's predictions should be valid probability distributions (non-negative and sum to 1).
- When converting logits to probabilities via softmax, always use the numerically stable form: subtract the max before exponentiating (`x = x - np.max(x); p = np.exp(x); p /= p.sum()`). A naive `np.exp(x) / np.sum(np.exp(x))` overflows to Inf/NaN for large logits. Alternatively, use `scipy.special.softmax`.


## PROPOSAL
Propose a novel theory from scratch based on all the information available, faithfully implementing the mechanism family the arbiter prescribed above. Do NOT simply reuse anything generated in past rounds.

## RESPONSE FORMAT
Return a JSON object with the following fields:
- theory: The theoretical claim this theory makes about cognition.
- predict: Python source defining def predict(parameters, state, history) -> np.ndarray.
- policy: Python source defining def policy(probs) -> int.
- parameters: Parameter ranges (e.g. "[1.0, 10.0]") or choices (e.g. "{1, 2}"), sampled per subject.
- rationale: Reasoning behind this theory design; used to explain why this theory is better then the previous ones.


## Response

```json
{
  "theory": "Conflict-modulated continuous anti-validity (CMCAV). Subjects form a continuous validity-weighted difference D = sum_j v_j^gamma_i * (A_j - B_j), mostly apply a negative validity-weighting sign, and respond through a graded evidence gate whose gain G(C) depends on the conflict structure of the validity-weighted evidence. The gate has no fixed threshold and no single fixed half-saturation constant: instead, the same continuous D is divided by a subject-level saturation plus trial-level leak, and is multiplied by a subject-level gain that is large when the evidence is concentrated in one or a few high-validity experts and small when the evidence comes from many low-validity or mutually conflicting experts. A small sign-dependent feature-tally term T handles count-driven designs where D is near zero.",
  "predict": "import numpy as np\n\n\ndef predict(parameters, state, history):\n    \"\"\"Conflict-modulated continuous anti-validity (CMCAV).\n\n    D = sum_j v_j^gamma * (A_j - B_j)\n    Evidence gate:\n        G(C) large for concentrated high-validity evidence,\n        small for broad low-validity or mutually conflicting evidence.\n    S = sign * lam * G(C) * D / (kappa + abs(D) + r)\n        + bias + w_t * (1/n) * sum_j (A_j - B_j)\n    Most subjects use sign = -1 (anti-validity); a minority use +1.\n    \"\"\"\n    stim = np.asarray(state, dtype=float)\n    if stim.ndim != 2 or stim.shape[0] != 2:\n        raise ValueError(\n            \"CMCAV expects a (2, n_features) stimulus; \"\n            f\"got shape {stim.shape}.\"\n        )\n\n    a = stim[0]\n    b = stim[1]\n\n    v = np.asarray(parameters[\"validities\"], dtype=float)\n    if v.size != a.size:\n        raise ValueError(\n            f\"validities length {v.size} does not match n_features {a.size}.\"\n        )\n\n    gamma = float(parameters[\"gamma\"])\n    lam = float(parameters[\"lam\"])\n    beta = float(parameters[\"beta\"])\n    bias = float(parameters[\"bias\"])\n    lapse = float(parameters[\"lapse\"])\n    kappa = float(parameters[\"kappa\"])\n    r = float(parameters[\"r\"])\n    p_positive = float(parameters[\"p_positive\"])\n    sign_draw = float(parameters[\"sign_draw\"])\n\n    eps_c = float(parameters[\"eps_c\"])\n    rho = float(parameters[\"rho\"])\n    nu = float(parameters[\"nu\"])\n    xi = float(parameters[\"xi\"])\n    g_min = float(parameters[\"g_min\"])\n    g_range = float(parameters[\"g_range\"])\n    c_half = float(parameters[\"c_half\"])\n\n    # Mostly negative validity-weighting sign.\n    sign = 1.0 if sign_draw < p_positive else -1.0\n\n    # Validity-weighted contributions.\n    w = np.power(v, gamma)\n    diff = a - b\n    contrib = w * diff\n    D = float(np.sum(contrib))\n\n    mag = np.abs(contrib)\n    M = float(np.sum(mag))\n    n_disc = int(np.sum(mag > 1e-12))\n\n    # Conflict-gated gain.\n    if M <= 1e-12:\n        G = g_min + 0.5 * g_range\n    else:\n        dom_idx = int(np.argmax(mag))\n        max_m = float(mag[dom_idx])\n        v_dom = float(v[dom_idx])\n\n        # Largest single-feature contribution relative to the net evidence.\n        ratio = max_m / (abs(D) + eps_c)\n        # Net-vs-total coherence; small when positive and negative\n        # validity-weighted contributions cancel.\n        coherence = abs(D) / M\n        # Penalize broad, many-feature evidence.\n        breadth = 1.0 + rho * max(0, n_disc - 2)\n\n        C = ratio * (v_dom ** nu) * (coherence ** xi) / breadth\n        C = float(np.clip(C, 0.0, 20.0))\n\n        G = g_min + g_range * C / (c_half + C)\n\n    G = float(np.clip(G, 0.0, 3.0))\n\n    # Small sign-dependent feature-tally term for count-driven designs.\n    T = float(np.mean(diff))\n    if D > 0.0:\n        wt = float(parameters[\"w_t_pos\"])\n    elif D < 0.0:\n        wt = float(parameters[\"w_t_neg\"])\n    else:\n        wt = 0.5 * (\n            float(parameters[\"w_t_pos\"]) + float(parameters[\"w_t_neg\"])\n        )\n\n    # Continuous anti-validity evidence response with no fixed threshold\n    # and no fixed half-saturation constant.\n    sat = D / (kappa + abs(D) + r)\n    score = sign * lam * G * sat + bias + wt * T\n    z = beta * score\n\n    # Numerically stable sigmoid.\n    if z >= 0.0:\n        p_a_core = 1.0 / (1.0 + np.exp(-z))\n    else:\n        ez = np.exp(z)\n        p_a_core = ez / (1.0 + ez)\n\n    p_a = (1.0 - lapse) * p_a_core + lapse / 2.0\n    p_a = float(np.clip(p_a, 0.0, 1.0))\n\n    return np.array([p_a, 1.0 - p_a], dtype=float)\n",
  "policy": "import numpy as np\n\n\ndef policy(probs):\n    p = np.asarray(probs, dtype=float)\n    if p.sum() <= 0.0:\n        p = np.ones_like(p) / len(p)\n    else:\n        p = p / p.sum()\n    return int(np.random.choice(len(p), p=p))\n",
  "parameters": {
    "gamma": "[1.6, 2.4]",
    "lam": "[0.8, 1.9]",
    "beta": "[1.5, 2.8]",
    "bias": "[-0.06, 0.06]",
    "lapse": "[0.03, 0.09]",
    "kappa": "[0.08, 0.22]",
    "r": "[0.00, 0.04]",
    "p_positive": "[0.02, 0.10]",
    "sign_draw": "[0.0, 1.0]",
    "w_t_pos": "[0.00, 0.10]",
    "w_t_neg": "[0.00, 0.10]",
    "eps_c": "[0.02, 0.08]",
    "rho": "[0.08, 0.30]",
    "nu": "[1.0, 2.0]",
    "xi": "[0.8, 1.8]",
    "g_min": "[0.02, 0.15]",
    "g_range": "[1.0, 2.5]",
    "c_half": "[0.25, 0.80]",
    "validities": "validities"
  },
  "rationale": "TAVU-tn imposed a fixed threshold/dead zone and a mostly all-or-none sign rule, which made low-contrast jumbled designs either flat or sharply thresholded and produced the wrong signs in Experiments 12-14. CNVW-tau used one fixed half-saturation tau for every evidence configuration, so it could not simultaneously produce a strong low-D gradient in one-hot staircase designs and a weak low-D contrast in jumbled conflict designs. CMCAV replaces the fixed threshold and fixed tau with a continuous saturating divisor plus a conflict-gated gain G(C). G(C) uses the largest single validity-weighted contribution relative to |D|, penalizes broad multi-feature or mutually conflicting evidence, and is modulated by the validity of the dominant expert. This gives steep serialized responding when a few high-validity experts concentrate the evidence, but near-flat responding when many low-validity or opposing experts produce small net D. The small sign-dependent tally term captures count-driven experiments where D is small but the raw feature tally is informative. The model stays continuous and probabilistic, with mostly negative anti-validity signs and no dead zone."
}
```

## Usage

```json
{
  "input_tokens": 22870,
  "output_tokens": 30843,
  "reasoning_tokens": 28792,
  "provider": "Baidu"
}
```
