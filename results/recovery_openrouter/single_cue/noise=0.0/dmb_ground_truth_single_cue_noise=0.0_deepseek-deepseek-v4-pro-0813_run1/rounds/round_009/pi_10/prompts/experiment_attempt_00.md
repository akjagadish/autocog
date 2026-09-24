# experiment_attempt_00

## System Prompt

You are a renowned cognitive scientist designing an experiment in the Decision Making (Binary Features) domain.

Your goal is to be an adversarial collaborator: propose a design whose outcomes would be predicted by your advocated theory but NOT by the competing theory. Both are provided below.

A useful proposal targets a *quantitative* dissociation between the two theories — how they respond differently to specific stimuli in addition to differences in overall performance.


## User Prompt

## EXPERIMENTAL DOMAIN
Subjects repeatedly choose between two fictitious products, A and B. Each option is described by a vector of binary expert ratings (each 0 or 1). Every experiment fixes its own feature count (via `validities` length) and per-expert validities; both are LLM-proposed. The validities are communicated to the subject in the instructions. Subjects pick whichever product they believe is of higher quality. There is no trial-by-trial correctness feedback.

A multi-attribute decision-making experiment. On each trial the subject sees two options (A, B), each described by `n_features` integer expert ratings (`n_features` is set by the length of `validities` you propose). Choose `validities` — one per feature, each in [0.5, 1.0], order free — to fix each expert's advertised accuracy; subjects are told these values up front. Then choose `trial_a_ratings/trial_b_ratings` (each rating value in [0, 1]) so that the intended decision-making theories make distinguishable predictions: avoid degenerate pairs where every theory agrees, and prefer pairs that maximally dissociate the candidate theories. Validities and the trial ratings together define the design; they are fixed across all trials in this experiment. No trial-by-trial correctness feedback. The total number of trials per subject is held at roughly 96: each unique pair is repeated K = max(1, 96 // n_unique_pairs) times in an independently-randomized order per subject.

Subjects see the following instructions:
In this experiment you will repeatedly choose between two fictitious products, A and B. On every trial you will see `n_features` expert ratings for each product (the number of experts is fixed across all trials and is set by the length of `validities`).

Each rating is an integer in [0, 1]. The ratings are displayed as a horizontal filled bar with the numeric value (e.g. "0/1") shown next to it. Higher = more positive.

The same experts (in the same order) provide ratings for both products on every trial. Each expert's accuracy (their validity expressed as a percentage, e.g. "Expert 1 (80%)") is shown next to their rating on every trial AND is also listed up front in an "Expert accuracies" panel.

On each trial, decide which product is of higher quality and press A for product A or B for product B. There is no time limit and no feedback. Note that for the first ~`min_rt_ms` of each trial the answer prompt is hidden and the keys are locked, so subjects first see the full ratings and can answer once the A / B prompt appears — design pairs that actually require comparing the ratings.

Total trials per subject is roughly `MAX_TRIALS`: each unique pair you propose is repeated `K = max(1, MAX_TRIALS // n_unique_pairs)` times in an independently-randomized order per subject.

## ADVOCATED THEORY
**Description:** Conflict-gated validity-gap compensation with strict homogeneous-bloc licensing and stronger opposition-sensitive lone amplification (GVC-strict). People anchor each advertised expert validity to the ensemble median. Below-median cues earn decision weight through a median/MAD-normalized deviance score. A single diagnostically deviant low cue is strongly amplified, with amplification increasing in the number of opposed at-or-above-median cues. When multiple below-median cues are diagnostic, a homogeneous low-deviant group is attenuated by cue count, but an extreme focal low cue is exempted from that group attenuation so it can still dominate the signed evidence. At-or-above-median cues receive no default weight; their validity-gap bonus is licensed only by a very homogeneous, sufficiently deviant bloc of three or more simultaneously diagnostic below-median cues, and is sharply damped by low-versus-high conflict. Choice is a fixed-temperature softmax with no lapse floor.

**Parameters:**
- c: [0.008, 0.012]
- w0: [0.007, 0.012]
- kappa: [1.9, 2.3]
- gamma: [1.25, 1.45]
- lambda: [4.5, 5.5]
- sigma: [0.10, 0.18]
- phi: [0.55, 0.75]
- nu: [0.15, 0.25]
- opp_cap: {5}
- focal_ratio: [3.0, 4.0]
- gate_base: {0.0}
- lone_floor: [0.00, 0.03]
- D_half: [0.35, 0.55]
- q_dev: {2}
- b_boost: [0.02, 0.08]
- D_boost: [0.6, 1.2]
- H_spread: [0.005, 0.02]
- K: [0.30, 0.50]
- w_hi0: {0.0}
- rho: [0.08, 0.14]
- alpha: [1.1, 1.8]
- beta: [1.4, 1.8]
- validities: validities

**`predict source code`:**
```python
import numpy as np


def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError('GVC expects a (2, n_features) stimulus.')

    validities = np.asarray(parameters['validities'], dtype=float).reshape(-1)
    n_feat = validities.shape[0]
    if n_feat != stim.shape[1]:
        raise ValueError('validities length must match n_features.')

    c = float(parameters['c'])
    median = float(np.median(validities))
    abs_dev = np.abs(validities - median)
    mad = float(np.median(abs_dev))
    scale = mad + c
    if scale <= 1e-12:
        scale = 1e-12

    dev = np.maximum(0.0, median - validities) / scale
    below = validities < median - 1e-12
    at_or_above = ~below
    gap = np.maximum(0.0, validities - median) / scale

    w0 = float(parameters['w0'])
    kappa = float(parameters['kappa'])
    gamma = float(parameters['gamma'])
    lam = float(parameters['lambda'])
    sigma = float(parameters['sigma'])
    phi = float(parameters['phi'])
    nu = float(parameters['nu'])
    opp_cap = float(parameters['opp_cap'])
    focal_ratio = float(parameters['focal_ratio'])

    raw = np.zeros(n_feat, dtype=float)
    dev_bounded = np.minimum(dev, 100.0)
    raw[below] = w0 + kappa * np.power(dev_bounded[below], gamma)

    diff = stim[0] - stim[1]
    active_below = below & (np.abs(diff) > 1e-12)
    n_active = int(np.count_nonzero(active_below))

    def lone_amplification(idx):
        base_amp = 1.0 + lam * np.tanh(float(dev[idx]) / sigma)
        opp = at_or_above & (np.abs(diff) > 1e-12) & (diff * diff[idx] < 0.0)
        n_opp = int(np.count_nonzero(opp))
        return base_amp * (1.0 + nu * min(float(n_opp), opp_cap))

    if n_active == 1:
        focal = int(np.flatnonzero(active_below)[0])
        raw[focal] = raw[focal] * lone_amplification(focal)
    elif n_active >= 2:
        att = 1.0 / (1.0 + phi * (n_active - 1))
        active_devs = dev[active_below]
        i_max = int(np.argmax(active_devs))
        max_dev = float(active_devs[i_max])
        med_dev = float(np.median(active_devs))
        if med_dev > 1e-12 and max_dev > focal_ratio * med_dev:
            focal = int(np.flatnonzero(active_below)[i_max])
            others = below.copy()
            others[focal] = False
            raw[others] = raw[others] * att
            raw[focal] = raw[focal] * lone_amplification(focal)
        else:
            raw[below] = raw[below] * att

    gate_base = float(parameters['gate_base'])
    lone_floor = float(parameters['lone_floor'])
    D_half = float(parameters['D_half'])
    q_dev = float(parameters['q_dev'])
    b_boost = float(parameters['b_boost'])
    D_boost = float(parameters['D_boost'])
    H_spread = float(parameters['H_spread'])
    K = float(parameters['K'])

    gate = gate_base
    if n_active == 1:
        gate *= lone_floor

    if n_active > 0:
        active_devs = dev[active_below]
        dmax = float(np.max(active_devs))
    else:
        dmax = 0.0

    if dmax > 1e-12:
        gate *= 1.0 / (1.0 + (dmax / D_half) ** q_dev)

    if n_active >= 3:
        low_vals = validities[active_below]
        spread = float(np.std(low_vals))
        spread_norm = spread / scale
        hom = 1.0 / (1.0 + (spread_norm / H_spread) ** 12.0)
        mean_dev = float(np.mean(dev[active_below]))
        act = float(np.tanh(mean_dev / D_boost))
        gate += b_boost * hom * act

    w_hi0 = float(parameters['w_hi0'])
    rho = float(parameters['rho'])
    alpha = float(parameters['alpha'])

    gap_bounded = np.minimum(gap, 100.0)
    hi_pre = np.zeros(n_feat, dtype=float)
    if np.any(at_or_above):
        hi_pre[at_or_above] = w_hi0 + rho * np.power(gap_bounded[at_or_above], alpha)

    E_low = float(np.dot(raw, diff))
    E_high_pre = float(np.dot(hi_pre, diff))

    if E_low * E_high_pre < 0.0:
        conflict = 2.0 * min(abs(E_low), abs(E_high_pre)) / (abs(E_low) + abs(E_high_pre) + 1e-12)
        gate *= 1.0 / (1.0 + (conflict / K) ** 2.0)

    gate = float(np.maximum(gate, 0.0))

    raw_high = np.zeros(n_feat, dtype=float)
    if np.any(at_or_above):
        raw_high[at_or_above] = w_hi0 + rho * np.power(gap_bounded[at_or_above], alpha) * gate

    raw_all = raw + raw_high
    total = float(np.sum(raw_all))
    if total <= 0.0:
        weights = np.ones(n_feat, dtype=float) / float(max(n_feat, 1))
    else:
        weights = raw_all / total

    evidence_A = float(np.dot(weights, diff))

    beta = float(parameters['beta'])
    logits = np.array([evidence_A, 0.0], dtype=float)
    z = beta * (logits - float(np.max(logits)))
    e = np.exp(z)
    probs = e / np.sum(e)
    return probs
```

**`policy source code`:**
```python
import numpy as np


def policy(probs):
    probs = np.asarray(probs, dtype=float)
    probs = probs / probs.sum()
    return int(np.random.choice(probs.shape[0], p=probs))
```


## COMPETING THEORY
**Description:** Median anchoring of advertised validities gives below-median cues MAD-normalized deviance weight. Lone diagnostic low cues receive strong amplification, while multiple diagnostic low cues receive count-based attenuation that is deviance-selective: an extreme below-median singleton is partially exempt from attenuation without demoting inactive low cues. Above-median cues contribute through a sign-flexible rank-ordered consensus term gated by the signed evidence carried by actually diagnostic low cues. Balanced low evidence permits a negative consensus weight, opposing low evidence gates the high-cue term toward zero, and weak low evidence permits only a small capped positive rank bonus. Large comparable multi-low coalitions receive a linear soft attenuation of their total active low evidence to prevent aligned low blocs from over-saturating choice. Choice is a fixed-temperature softmax with a tiny lapse floor.

**Parameters:**
- c: [0.008, 0.012]
- w0: [0.007, 0.012]
- kappa: [1.9, 2.3]
- gamma: [1.25, 1.45]
- lone_gain: [5.5, 6.5]
- lone_sigma: [0.10, 0.18]
- phi: [1.2, 1.5]
- nu: [0.15, 0.25]
- opp_cap: {5}
- out_gain: [0.50, 0.80]
- out_thresh: [2.2, 2.8]
- out_slope: [3.5, 5.5]
- cap_out_gate: {0.45}
- n_cap_min: {4}
- low_multi_scale: [0.60, 0.80]
- rho_hi: [0.025, 0.035]
- alpha_hi: [3.0, 4.5]
- h_cap: [0.06, 0.12]
- h_pos: [0.15, 0.25]
- h_neg: [1.30, 1.55]
- min_low_mass: {0.10}
- low_bal_eps: {0.02}
- weak_thresh: [0.12, 0.20]
- n_min_hi: {2}
- cons_thresh: [0.82, 0.88]
- cons_s: {0.04}
- beta: [1.85, 2.20]
- epsilon: {0.001}
- validities: validities

**`predict source code`:**
```python
import numpy as np


def predict(parameters, state, history):
    stim = np.asarray(state, dtype=float)
    if stim.ndim != 2 or stim.shape[0] != 2:
        raise ValueError('DSA-SFCC expects a (2, n_features) stimulus.')

    validities = np.asarray(parameters['validities'], dtype=float).reshape(-1)
    n_feat = validities.shape[0]
    if n_feat != stim.shape[1]:
        raise ValueError('validities length must match n_features.')

    c = float(parameters['c'])
    median = float(np.median(validities))
    abs_dev = np.abs(validities - median)
    mad = float(np.median(abs_dev))
    scale = mad + c
    if scale <= 1e-12:
        scale = 1e-12

    dev = np.maximum(0.0, median - validities) / scale
    below = validities < median - 1e-12
    above = validities > median + 1e-12
    at_or_above = ~below
    gap = np.maximum(0.0, validities - median) / scale

    w0 = float(parameters['w0'])
    kappa = float(parameters['kappa'])
    gamma = float(parameters['gamma'])
    lone_gain = float(parameters['lone_gain'])
    lone_sigma = float(parameters['lone_sigma'])
    phi = float(parameters['phi'])
    nu = float(parameters['nu'])
    opp_cap = float(parameters['opp_cap'])

    raw = np.zeros(n_feat, dtype=float)
    dev_bounded = np.minimum(dev, 100.0)
    raw[below] = w0 + kappa * np.power(dev_bounded[below], gamma)
    pre_att_raw = raw.copy()

    diff = stim[0] - stim[1]
    active_below = below & (np.abs(diff) > 1e-12)
    n_active = int(np.count_nonzero(active_below))
    use_low_cap = False

    def lone_amplification(idx):
        base_amp = 1.0 + lone_gain * np.tanh(float(dev[idx]) / lone_sigma)
        opp = at_or_above & (np.abs(diff) > 1e-12) & (diff * diff[idx] < 0.0)
        n_opp = int(np.count_nonzero(opp))
        return base_amp * (1.0 + nu * min(float(n_opp), opp_cap))

    if n_active == 1:
        focal = int(np.flatnonzero(active_below)[0])
        raw[focal] = raw[focal] * lone_amplification(focal)
    elif n_active >= 2:
        base_att = 1.0 / (1.0 + phi * (n_active - 1))
        d_act = dev[active_below]
        d_ref = float(np.median(d_act)) + 1e-12
        out_slope = float(parameters['out_slope'])
        out_thresh = float(parameters['out_thresh'])
        out_gain = float(parameters['out_gain'])

        ratio = np.clip(d_act / d_ref, 0.0, 20.0)
        outlier = 1.0 / (1.0 + np.exp(-out_slope * (ratio - out_thresh)))
        att_factors = base_att + (1.0 - base_att) * out_gain * outlier
        raw[active_below] = raw[active_below] * att_factors

        outlier_max = float(np.max(outlier))
        cap_out_gate = float(parameters['cap_out_gate'])
        n_cap_min = int(float(parameters['n_cap_min']))
        use_low_cap = (outlier_max < cap_out_gate) and (n_active >= n_cap_min)

    high_base = np.zeros(n_feat, dtype=float)
    above_idx = np.flatnonzero(above)
    if above_idx.size > 0:
        hi_gap = gap[above]
        order = np.argsort(hi_gap)
        m = above_idx.size
        ranks = np.empty(m, dtype=float)
        ranks[order] = np.arange(1, m + 1, dtype=float)
        if m > 1:
            u = (ranks - 1.0) / (m - 1.0)
        else:
            u = np.ones(m, dtype=float)
        rho_hi = float(parameters['rho_hi'])
        alpha_hi = float(parameters['alpha_hi'])
        bonus = rho_hi * np.power(np.clip(u, 0.0, 1.0), alpha_hi)
        high_base[above] = bonus
        total_hi = float(np.sum(high_base))
        h_cap = float(parameters['h_cap'])
        if total_hi > h_cap and total_hi > 1e-12:
            high_base[above] *= h_cap / total_hi

    total_low = float(np.sum(raw))
    E_low = float(np.dot(raw, diff))
    total_hi = float(np.sum(high_base))
    E_high = float(np.dot(high_base, diff))

    active_low_mass = float(np.sum(raw[active_below]))
    low_strength = abs(E_low) / (active_low_mass + 1e-12) if active_low_mass > 1e-12 else 0.0
    low_bal_eps = float(parameters['low_bal_eps'])
    min_low_mass = float(parameters['min_low_mass'])
    pre_att_active_mass = float(np.sum(pre_att_raw[active_below]))
    has_low_evidence = pre_att_active_mass > min_low_mass
    low_bal = 1.0 if (has_low_evidence and low_strength <= low_bal_eps) else 0.0
    weak_thresh = float(parameters['weak_thresh'])
    low_weak = 1.0 / (1.0 + (low_strength / weak_thresh) ** 2)

    active_high = above & (np.abs(diff) > 1e-12)
    n_ha = int(np.count_nonzero(active_high))
    consensus = 0.0
    if n_ha > 0:
        w_act = high_base[active_high]
        total_act = float(np.sum(w_act))
        if total_act > 1e-12:
            E_act = float(np.dot(w_act, diff[active_high]))
            align_share = 0.5 + 0.5 * abs(E_act) / total_act
            n_min_hi = float(parameters['n_min_hi'])
            size_factor = float(np.tanh(n_ha / max(n_min_hi, 1e-12)))
            consensus = align_share * size_factor

    cons_thresh = float(parameters['cons_thresh'])
    cons_s = float(parameters['cons_s'])
    zz = (cons_thresh - consensus) / cons_s
    zz = float(np.clip(zz, -60.0, 60.0))
    strong = 1.0 / (1.0 + float(np.exp(zz)))

    strong_neg = low_bal * strong
    h_pos = float(parameters['h_pos'])
    h_neg = float(parameters['h_neg'])
    g = h_pos * low_weak * (1.0 - strong_neg) - h_neg * strong_neg
    g = float(np.clip(g, -h_neg, h_pos))

    E_low_evidence = E_low
    if use_low_cap:
        low_multi_scale = float(parameters['low_multi_scale'])
        E_low_evidence = low_multi_scale * E_low

    denom = total_low + total_hi
    if denom <= 1e-12:
        evidence = 0.0
    else:
        evidence = (E_low_evidence + g * E_high) / denom

    beta = float(parameters['beta'])
    logits = np.array([evidence, 0.0], dtype=float)
    z = beta * (logits - float(np.max(logits)))
    z = np.clip(z, -60.0, 60.0)
    e = np.exp(z)
    core = e / np.sum(e)

    epsilon = float(parameters['epsilon'])
    probs = (1.0 - epsilon) * core + epsilon * np.ones(2, dtype=float) / 2.0
    probs = probs / np.sum(probs)
    return probs
```

**`policy source code`:**
```python
import numpy as np


def policy(probs):
    probs = np.asarray(probs, dtype=float)
    probs = probs / probs.sum()
    return int(np.random.choice(probs.shape[0], p=probs))
```


## ALREADY-EXPLORED EXPERIMENTS (do not repeat)
[0] Eight experts are used. Expert 0 is advertised as 90% accurate; the remaining seven are clearly lower (75% down to 50%). Every critical trial makes Expert 0 discriminate: it favors one option. The seven lower experts are arranged so that k = 0,1,...,7 of them favor the opposite option. Take The Best stops at Expert 0 and therefore predicts a constant probability of choosing the top-cued option across all k. Tallying counts all eight experts; the tally margin for the top-cued option is 8 - 2k, so its predicted choice probability is a decreasing sigmoid in k, crossing chance at k=4 and reversing for k>4. Two mirrored blocks are included (Expert 0 favors A in one block, B in the other) to double observations and control for response bias. This yields a strong quantitative dissociation: a flat psychometric function over k under Take The Best versus a negatively sloped sigmoid under Tallying. The 16 unique pairs are repeated 6 times for roughly 96 trials.

[1] Six experts with validities 0.90, 0.80, 0.70, 0.60, 0.55, 0.50 define a fixed TTB cue order. The 16 unique pairs form a cue-locus × tally-margin design. In A-first trials (A0-A7) the first discriminating cue in validity order favors A; in B-first trials (B0-B7) it favors B. Higher-validity cues are tied on r=1 and r=2 trials so the first discriminator is not always the top expert, extending the already-explored design. Lower cues are arranged to produce tally margins (#A wins - #B wins) of -4, -3, -2, 0, +2, +3, +4. TTB stops at the first discriminator, so it predicts a single p(A) for all A-first trials and a single p(A) for all B-first trials, independent of the lower-cue margin. Tallying counts all six cues, so it predicts p(A) = sigmoid(beta * margin), increasing monotonically with the margin and equal to chance at margin 0. Thus TTB predicts a flat step function in margin within each first-discriminator direction, whereas Tallying predicts a graded psychometric function; zero-margin trials additionally oppose TTB's directional prediction to Tallying's chance prediction. The 16 unique pairs are repeated K=6 times for 96 trials.

[2] Six experts with validities 0.92, 0.84, 0.76, 0.68, 0.58, 0.50. The design holds the Tallying score constant within two blocks while varying validity-weighted evidence. The first eight trials are zero tally-margin pairs: A wins exactly one feature and B wins exactly one feature, so Tallying gives a 1-1 tie and predicts p(A)=0.5 for every pair. The discriminating feature pair is varied from (A wins the 50% expert, B wins the 92% expert) to the reverse, so the advocated validity-weighted evidence increases monotonically from w5-w0 to w0-w5, predicting a psychometric curve from below to above chance. The last eight trials are constant +2 tally-margin pairs: A wins 4 features, B wins 2, so Tallying predicts the same p(A)=sigmoid(2*beta) for all eight. The four A-win features are chosen along a dominance chain (each adjacent pair swaps one A-win from a lower-validity to a higher-validity feature), so the validity-weighted evidence strictly increases for any monotone validity-weighting function. With offset=0.5, gamma=1 the +2 block runs from -0.24 (weighted favors B despite A winning 4 of 6 features) to +1.12. Thus Tallying predicts two flat lines (0.5 and a single >0.5 value), while the advocated theory predicts two increasing psychometric functions of weighted evidence. The 16 unique pairs are repeated K=6 for about 96 trials.

[3] Twelve experts: six high-validity (0.94-0.99) and six low-validity (0.50-0.55). The eight unique pairs form four groups. Group A (A1-A3): A wins 3-5 high-validity features while B wins 4-6 low-validity features, so Tallying margin is -1 (predicts p(A)<0.5), but validity-weighted evidence is positive (predicts p(A)>0.5). Group B (B1-B3): A wins 4-6 low-validity features while B wins 3-5 high-validity features, so Tallying margin is +1 (predicts p(A)>0.5), but validity-weighted evidence is negative (predicts p(A)<0.5). Groups C and D have zero Tallying margin (predicts p(A)=0.5) but all-high vs all-low wins give positive and negative validity-weighted evidence respectively. Thus Tallying and validity-weighted integration make opposite directional predictions for every pair, and the within-group graded evidence allows estimating beta for both accounts.

[4] This design tests whether low-validity experts are overweighted (reversed-validity) against the equal-count Tallying benchmark. Two experts are advertised near chance (50%, 51%) and seven are near-perfect (98%–99.5%). On every trial the two low-validity experts favor one option while k = 0…7 high-validity experts favor the other option; all remaining experts are tied. In A-low trials Tallying gives A exactly 2 wins and B k wins, so its tally margin is 2 − k: it crosses chance at k = 2 and predicts B for k ≥ 3. Reversed-validity instead gives the 50%/51% experts weights of about 0.75–0.81 each (the largest weights) and the 98%–99.5% experts weights of about 0.12–0.31 each. The two low weights sum to about 1.5–1.6, which outweighs six of the seven high weights (and all seven for gamma ≈ 0.4). Thus reversed-validity predicts A for k = 0…6 in A-low trials and B for k = 0…6 in B-low trials. The critical k = 2…6 trials therefore produce opposite directional predictions: Tallying chooses the high-validity side (or guesses at k = 2), while reversed-validity chooses the low-validity side. The psychometric crossover is shifted from k = 2 under Tallying to k = 7 or beyond under reversed-validity, a large quantitative dissociation. The two mirrored blocks double observations and control for response bias.

[5] Eight experts with four near-chance validities (0.50-0.53) and four near-perfect validities (0.97-0.995). Reversed-validity weights near-chance experts heavily (weight roughly 0.74-0.81) and discounts near-perfect experts (weight roughly 0.12-0.29), while Tallying gives every expert equal unit weight. The 16 unique pairs form two blocks. Block 1 (pairs 1-8) holds the Tallying margin at 0 (A wins exactly 3 features, B wins exactly 3, 2 ties), so Tallying predicts p(A)=0.5 for every pair. The pairs swap A's wins from low-validity to high-validity features, so reversed-weighted evidence decreases from about +1.7 to -1.7, predicting a graded psychometric curve crossing chance. Block 2 (pairs 9-16) holds the Tallying margin at +2 (A wins 5, B wins 3), so Tallying predicts the same >0.5 p(A) for all eight pairs. The same low-to-high validity swap makes reversed-weighted evidence decrease from about +2.8 to -0.7, so reversed-validity predicts a decreasing curve that crosses below chance on the last three pairs, opposite in direction to Tallying. Thus Tallying predicts two flat lines (0.5 and a single >0.5 value), whereas reversed-validity predicts two graded psychometric functions of weighted evidence, with several pairs yielding opposite directional predictions.

[6] Nine experts are used: three near-chance experts (0.53, 0.52, 0.51) and six higher-validity experts (0.99 down to 0.90). The three near-chance experts are deliberately close together. In the competing theory they become the top three normalized weights, each about 0.32 to 0.33, so the top3-similarity gate is near 1 and the effective-n gate is near 3; this holds the context-gated beta roughly constant. All six higher validities together contribute less than about 0.02 of normalized weight, so the competing theory's evidence is set almost entirely by which option wins more of the three low-validity experts. Block A has A win two low experts and B win one, giving competing evidence about +0.33 for A on every trial, so p(A) stays near 0.65 to 0.70 regardless of the high-feature pattern. Block B mirrors this, giving competing evidence about -0.33 and p(A) near 0.30 to 0.35. The advocated theory does not normalize and weights each expert by max(1 - v, 0)^gamma. Its low-expert weights are near 0.80, but its high-expert weights remain substantial, from about 0.50 for the 0.90 expert down to about 0.25 for the 0.99 expert. Eight high-feature patterns are chosen so that the B-winning high-feature weight total S equals 0, 0.349, 0.752, 0.951, 1.202, 1.511, 1.707, or 2.267. In the two-low A block, advocated evidence for A therefore runs +3.08, +2.38, +1.58, +1.18, +0.68, +0.06, -0.33, -1.45, giving p(A) from near ceiling to near floor and crossing chance between the last two intermediate patterns. In the mirrored block it runs +1.45, +0.76, -0.05, -0.45, -0.95, -1.57, -1.96, -3.08. Thus the competitor predicts a flat line within each low-split block, while the advocated theory predicts a steep psychometric function of the high-validity pattern; four pairs are directionally opposite. The 16 unique pairs repeated 6 times give roughly 96 trials.

[7] This nine-expert design isolates ensemble-normalized cue weighting from fixed reversed-validity weighting. The validities are two 0.50 experts and seven 0.80-0.84 experts, so the median is 0.80. Under the advocated normalization, only the two 0.50 experts lie below the median and receive large deviance weights; the seven 0.80-0.84 experts have zero or negative deviance and receive only the tiny baseline w0. After normalization the two low-validity experts carry nearly all decision weight, giving effective_n near 2 and a softmax beta near 2.0. The competing reversed-diagnosticity model instead assigns weights near 0.78 to each 0.50 expert and weights near 0.53-0.57 to each 0.80-0.84 expert, so the seven high experts have about 3.9 total weight versus about 1.6 for the two low experts. The first eight trials hold the two low experts in a 1-1 split and sweep the high-validity block from all favoring B to all favoring A. The advocated theory predicts a flat p(A) near 0.50 across all eight patterns because the high experts are normalized into near-zero weights. The competing theory predicts a sharp psychometric step from near floor to near ceiling as the high-expert evidence crosses zero. The second eight trials give both low experts to A and repeat the same high-block sweep. The advocated theory again predicts a flat line near 0.82 because evidence is approximately +1.0 and beta is about 2.0, while the competing theory predicts a steep psychometric function shifted by the low-expert advantage. This yields a strong quantitative dissociation: two flat lines under the advocated theory versus two steep high-block psychometric functions under the competing theory, with several pairs producing opposite directional predictions. The 16 unique pairs are repeated K = 6 times for about 96 trials.

[8] Four tied low-validity experts at 0.50 and five tied high-validity experts at 0.85 give bottom_share = 4/9 = 0.444, which crosses the advocated theory's 0.42 threshold and engages its delta_high floor. The tied high ranks then receive a non-negligible normalized weight floor, about 0.20 to 0.25 of total decision weight. By contrast, the competing theory computes the median as 0.85 because the five high experts are the majority, so the high experts sit exactly at the ensemble median, receive only the tiny baseline w0, and are essentially ignored. The four low experts lie below the median and carry nearly all competing decision weight. In the low-tie block the four low experts are split 2 for A and 2 for B, so competing evidence is zero and the competing model predicts p(A) near 0.50 for every high-block split. The advocated model's high-validity floor makes high-block evidence vary from about -0.23 to +0.23 as the number of high experts favoring A goes from 0 to 5, so its predicted p(A) moves from about 0.33 to 0.67. In the A-majority low block (3 low experts favor A) the competing model predicts a flat p(A) near 0.70, while the advocated model predicts an increasing curve from about 0.61 to 0.86. In the B-majority low block the competing model predicts a flat p(A) near 0.30, while the advocated model predicts an increasing curve from about 0.14 to 0.39. This yields three flat lines under the competing theory and three monotonic high-block psychometric curves under the advocated theory, providing strong quantitative dissociations. Sixteen unique pairs are repeated six times for about 96 trials.

[9] Eleven experts: one lone 50% cue and ten tightly clustered 84.0%-86.7% cues. The median validity is 85.2% and MAD is about 0.9 percentage points, so under the advocated normalized-deviance model the 50% cue is a huge deviance outlier. It receives roughly 96% of normalized weight, while the three just-below-median experts swept in the design (84.0%, 84.3%, 84.6%) together carry only about 3% of weight and the higher experts carry almost none. This near-monopoly activates the single-cue high-share/gap gate and quenches the softmax beta to its low floor, so the advocated model predicts essentially flat choice functions across the three-expert sign sweep: p(A) near 0.50 in the low-tie block and a nearly constant value above 0.50 in the low-favors-A block. In the competing rank model bottom_share is only 1/11, so delta=0 and beta_low near 1.7 applies. Rank weights give the lone 50% cue about 0.44 of total weight, while the top three swept high cues together retain about 0.50 of weight, so the same 2x2x2 sign sweep moves competing signed evidence from about -0.50 to +0.50 in the tie block (p(A) roughly 0.30 to 0.70) and from about -0.06 to +0.94 in the low-favors-A block (p(A) rising from below 0.50 to above 0.80). The first low-favors-A pair is a directional reversal: the lone low cue favors A while all three swept high cues favor B, giving advocated p(A) above 0.50 but competing p(A) around 0.47. Features 4-10 are tied at 1 in every trial so they do not affect either model. This one-low plus tight-high-validity ensemble is distinct from the already-explored two-, three-, and four-low designs.

[10] Validities are one 50% expert, four 80% experts (the ensemble median), and 85/90/95% experts. The 50% cue has huge normalized deviance (median=0.80, MAD≈0.025), so in the competing model it receives roughly 99.6% of normalized weight; its near-monopoly then quenches beta to its low floor, giving nearly flat p(A)≈0.57 when the low cue favors A and ≈0.43 when it favors B, regardless of the high-cue pattern. In the advocated model the same lone low cue is capped at cap_share≈0.375 (low_bloc_frac=1/8), and the cap redistributes the remaining ≈0.625 weight to the seven high-validity cues. The high-cue sweep therefore moves advocated signed evidence from about -0.25 to +1.00 in the low-A block and from -1.00 to +0.25 in the low-B block, producing a steep psychometric function that crosses chance. Key directional reversals include low-A k=0 (advocated p(A)≈0.35 vs competing≈0.57) and low-B k=7 (advocated≈0.65 vs competing≈0.43). The 16 unique pairs are two blocks (low cue favors A vs B) × k=0..7 high cues favoring A in ascending validity order; K=6 gives 96 trials.

[11] This 12-expert design sets the ensemble median to 0.85 and MAD to 0.05. Six cues are below the median: one 0.50 cue and five 0.80 cues; six 0.90 cues are above the median and are tied at 1 in every trial so they add no signed evidence. Under the advocated model the deviance of the 0.50 cue is 7 times the deviance of each 0.80 cue, so after normalization the lone 0.50 cue receives about 0.56-0.79 of decision weight while all five 0.80 cues together receive only about 0.21-0.44. The 0.90 cues receive only the tiny baseline weight. The top-share never reaches the single-cue floor gate, so beta stays in the normal range. Therefore the advocated model follows the lone 0.50 cue: in Block A, where the 0.50 cue favors A, it predicts p(A) above 0.5 even when all five 0.80 cues oppose A (k=0 and k=1); in Block B, where the 0.50 cue favors B, it predicts p(A) below 0.5 even when all five 0.80 cues favor A (k=4 and k=5). Under the competing model, low_bloc_frac is 6/12 = 0.5, which suppresses the rank-based baseline and sets cap_share near 0.263. The lone 0.50 cue is capped at about 0.263 and the remaining weight is redistributed to the five 0.80 cues, which together carry about 0.737 of decision weight. The competing model therefore follows the majority of the 0.80 cues, producing opposite directional predictions in those same critical pairs: Block A k=0 and k=1 predict p(A) below 0.5, while Block B k=4 and k=5 predict p(A) above 0.5. The k=0..5 sweep in each block also yields different psychometric slopes for the two theories. The 12 unique pairs repeated 8 times give roughly 96 trials.

[12] This design isolates a beta-gating dissociation between the two theories. Three tied low-validity experts (50%) and five tied high-validity experts (90%) are used. The median validity is 0.90 and MAD is 0, so the three 50% experts have enormous median/MAD deviance and dominate normalized decision weight in both theories. The high experts sit exactly at the median and contribute negligible signed evidence in both theories. The critical difference is the choice rule: in the competing theory, the three co-equal low-validity experts create an effective_n near 3 and top3 similarity near 1, activating the low gate and boosting beta to roughly 2.5-3.1, producing near-ceiling/floor choice probabilities when the low bloc favors A or B. In the advocated theory, the same three-way equal weight distribution has normalized entropy ln(3)/ln(8)=0.528, which falls below the concentration threshold H_thresh (0.75-0.90), so the concentration gate keeps beta near its low baseline (approximately 0.30-0.60); choices therefore remain moderate even when all three low experts favor one option. The 4x4 factorial of low-split (0-3 low experts favoring A) and high-split (1-4 high experts favoring A) provides a psychometric sweep that should be steep and near-saturating under the competing theory but shallow and moderate under the advocated theory.

[13] Sixteen experts are chosen so that one isolated below-median cue (0.849) can be tied on every trial, contributing zero signed evidence. Nine experts sit exactly at the ensemble median (0.850), and six higher-validity experts (0.860 to 0.915) form a top group that receives the largest rank-based baseline in the competing model. Because the lone below-median cue is tied, the advocated model stays in its ordinary beta regime (no near-monopoly and effective_n far from 3), while the competing model's beta drive is forced near its low baseline since low_evidence is zero on every trial. The 4 by 4 factorial sweeps j = 0, 2, 4, 6 top-group experts favoring A and k = 0, 2, 4, 6 median experts favoring A. Under the advocated model all high cues have identical w0 weight, so choice depends only on the total high tally t = j + k; all cells with equal j + k must give the same p(A). Under the competing model the six top-validity experts carry much larger rank-based baseline weight than the nine median experts, so p(A) increases as A wins shift from the median group to the top group. This creates a strong interaction: for fixed total high tally (e.g., t = 6: (0,6), (2,4), (4,2), (6,0)), the advocated model predicts a flat line while the competing model predicts a monotonic rank-weighted psychometric function, including trials near and above chance that are below chance under the advocated model.

[14] This nine-expert design uses a single below-median cue at 0.899 against an ensemble median of 0.900, with eight high/median cues from 0.900 up to 0.995. The below-median cue is diagnostic on every trial, while the high block is swept from all favoring B to all favoring A. Under the advocated theory, the lone 0.899 cue has only modest median/MAD deviance (MAD is 0.001, so deviance is roughly 0.09), giving it a moderate raw weight that does not monopolize the ensemble. The eight high cues receive rank-based baseline weight whose total is larger than the lone low weight. When the low cue favors A and all eight high cues favor B, the signed evidence becomes negative and conflict damping keeps beta low, predicting p(A) just below 0.5. When the high block sweeps toward A, evidence becomes strongly positive and p(A) rises to roughly 0.7. The mirrored low-favors-B block gives the reverse psychometric curve. In the competing theory, the solitary diagnostic below-median cue is multiplicatively amplified by the solitary-cue factor, while the high cues receive at most tiny gated bonuses, so the lone low cue controls the normalized evidence on every trial. The competing theory therefore predicts a nearly flat, low-cue-following probability in each block, near 0.82 to 0.88 in the low-A block and near 0.12 to 0.18 in the low-B block, irrespective of the high-block pattern. The critical dissociations are low-A k=0 and low-B k=8, where the advocated theory predicts p(A) below 0.5 while the competing theory strongly follows the lone low cue. The 18 unique pairs are two mirrored blocks by k=0..8 high cues favoring A, giving K=5 repetitions for roughly 90 trials.

[15] Thirteen experts are used with median validity 0.800 and MAD 0.0005. Experts 0 and 1 lie just below the median at 0.799 and 0.7995, six experts sit exactly at the median, and five high experts run from 0.850 to 0.995. Because MAD is tiny, the two below-median cues receive large median/MAD deviance. In the advocated DASH theory, a lone diagnostic below-median cue receives a strong solitary-cue amplification, while two simultaneously diagnostic below-median cues receive count-dependent attenuation, so the low cues dominate the normalized decision weight and the high cues contribute only w_hi0 plus a small gated rank bonus. DASH therefore predicts roughly flat low-cue-following psychometric curves: p(A) stays near 0.80 when the diagnostic low cue(s) favor A and near 0.20 when they favor B, irrespective of the number k of high cues favoring A. In the competing distinctive low-cue dominance theory, the two low cues are close together so distinctiveness is small, while the eleven at-or-above-median cues receive a larger rank-based baseline, especially for the high-validity experts. Sweeping the high bloc from all favoring B to all favoring A should therefore move the competing p(A) from below 0.50 to above 0.50 in the low-favors-A blocks, and from above 0.50 to below 0.50 in the low-favors-B blocks. The k=0 and k=2 lone-low trials are the strongest directional dissociations, and the paired-low trials test DASH count-dependent attenuation. Sixteen unique pairs are repeated K=6 times for about 96 trials.

[16] This design isolates a high-cue bonus dissociation between GVC-strict and DASH. Six identical below-median experts at 0.7985 are diagnostic on every trial and are split 3 for A and 3 for B, so signed low-cue evidence is exactly zero. Four median experts at 0.800 are tied on every trial. Five above-median experts (0.860, 0.880, 0.900, 0.950, 0.990) are swept from all favoring B to all favoring A (k = 0..5). In GVC-strict, the homogeneous bloc of six simultaneously diagnostic below-median cues licenses a validity-gap bonus for the above-median cues, and conflict damping is absent because low-cue evidence is zero. The signed high-cue evidence therefore moves GVC-strict p(A) monotonically from clearly below 0.5 at k = 0 to clearly above 0.5 at k = 5, crossing near k = 3/4. In DASH, the zero low-cue evidence makes its low_gate exactly zero, so the rank bonus on above-median cues is fully gated off; only the tiny w_hi0 baseline remains, producing an essentially flat p(A) near 0.50 at every k. The 12 pairs include the six high-sweep pairs and their A/B mirrors to double observations and control response bias; each unique pair is repeated K = 8 times for roughly 96 trials.

[17] Twenty-six experts are used. Experts 0 and 1 are at 0.7999, just below the 0.8000 ensemble median; experts 2 through 17 sit exactly at the median; experts 18 through 25 are at 0.9000, giving a real upper spread. Because the median and high experts are heavily represented, the MAD is 0 and the deviance scale is driven by the model c parameter, so the two low experts receive only a modest deviance weight rather than a near-monopoly. Every trial makes exactly one of the two low experts diagnostic while the other low expert is tied, so the diagnostic low-cue count is always 1. The critical manipulation sweeps k = 0, 2, 5, 8, 12, 16, 20, 24 median-or-above experts opposing the diagnostic low cue. In GVC-strict, the solo-low gate starts at zero, so all 24 median and 0.9000 experts receive exactly zero decision weight; the only weights are the amplified diagnostic low cue and the tied low cue. Its lone amplification includes the opposition multiplier that rises with k and caps at 5, so GVC-strict p(A) rises slightly from k = 0 to k = 5 and then stays flat. DASH instead gives the diagnostic low cue only a constant lone amplification, while the 24 high experts retain at least the w_hi0 baseline and the 0.9000 experts also receive a partly gated rank bonus. As k opposing high experts increases, DASH high-cue evidence becomes increasingly negative, so DASH p(A) falls across k and crosses below 0.50 around k = 16 to 20, reaching about 0.40 at k = 24. This creates an opposite-slope dissociation: GVC-strict rises and plateaus while DASH decreases and crosses chance. The two mirrored low-cue blocks control response bias, and each of the 16 unique pairs is repeated K = 6 times for 96 trials.

## RESPONSE FORMAT
Return a JSON object with the following fields:
- rationale: Reasoning behind this experimental design; used when interpreting results.
- validities: Per-expert validities, one per feature. Each must be in [0.5, 1.0]; order is free (no descending requirement — theories that depend on validity order re-sort internally). Length determines n_features for the whole experiment and must match the rating-list length in every trial pair. Pick a spread (at least one high validity and at least one low one) — uniform validities (e.g. all 0.7) make many candidate theories indistinguishable, so spread them out.
- trial_a_ratings: List of option-A rating vectors, one per trial. Each inner list has length equal to len(validities); each value is binary (0 or 1). `trial_a_ratings[i]` pairs with `trial_b_ratings[i]` on trial i.
- trial_b_ratings: List of option-B rating vectors, one per trial. Same length and shape constraints as `trial_a_ratings`. Pick trials that let the intended theories be dissociated; avoid trials where every theory agrees.


## Response

```json
{
  "rationale": "This design uses two identical below-median experts (0.799) that are diagnostic on every trial and always split one-for-A versus one-for-B, together with five tied median experts (0.800) and six above-median experts (0.910-0.985). The high above-median block is swept from all favoring B to all favoring A, with the k highest-validity above-median experts favoring A. Signed low-cue evidence is exactly zero on every trial. In GVC-strict, the high-cue gain is only licensed by three or more simultaneously diagnostic below-median cues; with n_active = 2 the gate is exactly zero, so all above-median cues receive zero weight and the model predicts p(A) = 0.50 for every k. In DSA-SFCC, the two low cues have pre-att active mass above 0.10 and zero low strength, so the low block is balanced. When the six high cues are aligned, the rank consensus is strong and the sign-flexible high gate becomes strongly negative, reversing the effect of the high block: all high favor B gives positive evidence for A (p(A) near 0.70-0.79), while all high favor A gives p(A) near 0.21-0.30. Intermediate k values trace the consensus transition, so DSA-SFCC predicts a strongly k-dependent, partly reversed psychometric function against the flat 0.50 line predicted by GVC-strict. A final low-side mirror of the all-high-B endpoint balances the physical assignment of the two identical low experts.",
  "validities": [
    0.799,
    0.799,
    0.8,
    0.8,
    0.8,
    0.8,
    0.8,
    0.91,
    0.925,
    0.94,
    0.955,
    0.97,
    0.985
  ],
  "trial_a_ratings": [
    [
      1,
      0,
      1,
      1,
      1,
      1,
      1,
      0,
      0,
      0,
      0,
      0,
      0
    ],
    [
      1,
      0,
      1,
      1,
      1,
      1,
      1,
      0,
      0,
      0,
      0,
      0,
      1
    ],
    [
      1,
      0,
      1,
      1,
      1,
      1,
      1,
      0,
      0,
      0,
      0,
      1,
      1
    ],
    [
      1,
      0,
      1,
      1,
      1,
      1,
      1,
      0,
      0,
      0,
      1,
      1,
      1
    ],
    [
      1,
      0,
      1,
      1,
      1,
      1,
      1,
      0,
      0,
      1,
      1,
      1,
      1
    ],
    [
      1,
      0,
      1,
      1,
      1,
      1,
      1,
      0,
      1,
      1,
      1,
      1,
      1
    ],
    [
      1,
      0,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1
    ],
    [
      0,
      1,
      1,
      1,
      1,
      1,
      1,
      0,
      0,
      0,
      0,
      0,
      0
    ]
  ],
  "trial_b_ratings": [
    [
      0,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1
    ],
    [
      0,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      0
    ],
    [
      0,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      0,
      0
    ],
    [
      0,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      0,
      0,
      0
    ],
    [
      0,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      0,
      0,
      0,
      0
    ],
    [
      0,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      0,
      0,
      0,
      0,
      0
    ],
    [
      0,
      1,
      1,
      1,
      1,
      1,
      1,
      0,
      0,
      0,
      0,
      0,
      0
    ],
    [
      1,
      0,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1,
      1
    ]
  ]
}
```

## Usage

```json
{
  "input_tokens": 12958,
  "output_tokens": 37737,
  "reasoning_tokens": 36659,
  "provider": "Baidu"
}
```
