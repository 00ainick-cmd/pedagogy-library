---
id: zpd-operationalization
title: ZPD Operationalization
category: 07-runtime-decisions
aliases: [zone-of-proximal-development, target-accuracy-band, optimal-difficulty-window]
evidence_strength: strong
effect_size: null  # Foundational sequencing rule. The ZPD itself has no single intervention effect size; the runtime claim — "target ~70-85% next-item accuracy" — derives from Wilson et al. (2019) Nature Comms (optimal training error ≈ 15.87% for gradient-descent learners) and converges with Atkinson's (1972) optimal-presentation results and Corbett & Anderson's (1995) BKT mastery cut. Effect-size magnitudes are reported in context inside the Evidence base where each underlying intervention is cited.
key_sources:
  - "Vygotsky, L. S. (1978). Mind in society: The development of higher psychological processes (M. Cole, V. John-Steiner, S. Scribner, & E. Souberman, Eds.). Cambridge, MA: Harvard University Press."
  - "Wood, D., Bruner, J. S., & Ross, G. (1976). The role of tutoring in problem solving. Journal of Child Psychology and Psychiatry, 17(2), 89-100. doi:10.1111/j.1469-7610.1976.tb00381.x"
  - "Chaiklin, S. (2003). The zone of proximal development in Vygotsky's analysis of learning and instruction. In A. Kozulin, B. Gindis, V. Ageyev, & S. Miller (Eds.), Vygotsky's educational theory in cultural context (pp. 39-64). Cambridge, UK: Cambridge University Press."
  - "Wilson, R. C., Shenhav, A., Straccia, M., & Cohen, J. D. (2019). The Eighty Five Percent Rule for optimal learning. Nature Communications, 10, 4646. doi:10.1038/s41467-019-12552-4"
  - "Metcalfe, J., & Kornell, N. (2005). A Region of Proximal Learning model of study time allocation. Journal of Memory and Language, 52(4), 463-477. doi:10.1016/j.jml.2004.12.001"
  - "Corbett, A. T., & Anderson, J. R. (1995). Knowledge tracing: Modeling the acquisition of procedural knowledge. User Modeling and User-Adapted Interaction, 4(4), 253-278. doi:10.1007/BF01099821"
  - "Van de Pol, J., Volman, M., & Beishuizen, J. (2010). Scaffolding in teacher-student interaction: A decade of research. Educational Psychology Review, 22(3), 271-296. doi:10.1007/s10648-010-9127-6"
last_reviewed: 2026-04-30
applies_to: [sequencing, decision]
contraindicated_when:
  - learner_state.first_exposure
  - material.uncalibrated_item_pool
  - task_type.motor_acquisition
  - learner_state.overwhelmed
runtime_triggers:
  - next_item_difficulty_due
  - accuracy_window_drift_detected
  - mastery_decision_pending
  - session_start_seeding
  - support_fade_decision_due
related: [item-difficulty-discrimination, bayesian-knowledge-tracing, mastery-thresholds, desirable-difficulties, expertise-reversal, faded-worked-examples, productive-failure, sm2-fsrs]
---

# ZPD Operationalization

## One-line claim

Pick the next item, prompt, or scaffold so the learner's expected probability of correct response on it falls in roughly 70-85% — high enough that they succeed often, low enough that genuine retrieval and error-driven update happen on most attempts.

## Evidence base

Vygotsky (1978) defined the zone of proximal development as the distance between what a learner can do unassisted and what they can do "under adult guidance or in collaboration with more capable peers" (p. 86). The construct is theoretical, not numerical: Vygotsky never specified an accuracy band. Chaiklin (2003), in *Vygotsky's Educational Theory in Cultural Context*, argues that the bare definition has been over-flattened in Western reception — Vygotsky's interest was diagnosing maturing psychological functions and tailoring instruction to them, not running a difficulty knob. Wood, Bruner, and Ross (1976), introducing "scaffolding" in the *Journal of Child Psychology and Psychiatry*, supplied the operational vocabulary that turned the ZPD into a tutoring move: contingent control of task elements just beyond the learner's solo capacity, faded as the learner takes over. Van de Pol, Volman, and Beishuizen (2010), reviewing a decade of scaffolding research in *Educational Psychology Review*, distill the operational core into three properties — contingency (support tuned to current performance), fading (support withdrawn as performance rises), and transfer of responsibility (the learner increasingly drives the task). The runtime translation of "the ZPD" is therefore a contingent-difficulty rule, not an attempt to measure a Vygotskian zone directly.

The numerical content of that rule comes from the adaptive-instruction and machine-learning literatures. Wilson, Shenhav, Straccia, and Cohen (2019), in *Nature Communications*, derived analytically that for stochastic-gradient-descent-based learners on binary classification tasks, the rate of learning is maximized when training error is approximately 15.87% — the "Eighty Five Percent Rule" — and confirmed the prediction in artificial neural networks and biologically plausible models. Metcalfe and Kornell's (2005) *Region of Proximal Learning* model, in the *Journal of Memory and Language*, showed empirically that when learners self-pace study they spend most time on items they judge "almost known" rather than items they already have or items they have no purchase on; the most efficient study allocation lives at the boundary of current competence. Corbett and Anderson (1995), in *User Modeling and User-Adapted Interaction*, set the Bayesian Knowledge Tracing mastery cut at p(known) = 0.95 and use a per-step probability-of-correct estimate to choose the next opportunity — the canonical implementation of "stay at the edge of competence" in intelligent tutoring systems. Across these traditions, the convergent operational target is a 70-85% expected-correct band: the upper bound (~85%) maximizes learning rate per unit time; the lower bound (~70%) is a library heuristic, not a published value, chosen to keep frustration and error consolidation tolerable. Below ~50% the learner is outside the ZPD and instruction should switch to worked examples ([worked-example-effect](../01-learning-science/worked-example-effect.md)); above ~90% the item is no longer carrying information and difficulty should advance.

The framework has explicit boundary conditions. The 85% rule is derived for gradient-descent learners on stable categorical tasks; Wilson et al. (2019) note the optimum shifts on materials where the learning algorithm or noise model differs. Chaiklin (2003) cautions that conflating the ZPD with any difficulty-window rule misses the original construct, which is about emerging functions, not running mean accuracy. Practical implication: the 70-85% band is the runtime's defensible operational proxy, not a theoretical equivalence. Use it for sequencing and pass/fail timing; do not use it to claim a Vygotskian diagnosis. For first-exposure encoding the rule does not apply at all — there is no stable "expected probability" to target until a model exists (see [cognitive-load-theory](../01-learning-science/cognitive-load-theory.md)).

## When to apply

- **Next-item difficulty selection is due** — When picking the next item from a calibrated pool, choose one whose model-estimated p(correct) sits in 0.70-0.85. The default sequencing operation across every adaptive delivery loop.
- **Accuracy window has drifted out of band** — When rolling accuracy on the last 5-10 attempts exceeds ~0.90 (too easy) or falls below ~0.55 (too hard), step difficulty up or down by one granularity unit before the next item. Drift correction is the runtime hook for contingency (Van de Pol et al., 2010).
- **Mastery decision pending** — When approaching a pass/fail boundary, route final-pass items to ~0.80-0.85 estimated correct at the cut, combined with item information (see [item-difficulty-discrimination](../07-runtime-decisions/item-difficulty-discrimination.md)) so the decision sits in the precision peak.
- **Session start seeding without prior estimate** — Without a stored ability estimate, open at population-mean difficulty (~0.70 expected correct for the median learner) and let the first 1-3 responses pin the working estimate before tightening the band.
- **Support-fade decision due** — When the learner has performed in band on N consecutive scaffolded attempts (typical N: 3 at ≥0.80), strip one layer of scaffolding and re-evaluate; this operationalizes contingent fading (Van de Pol et al., 2010; Wood et al., 1976).
- **Self-pacing the learner cannot be trusted to do** — Metcalfe and Kornell (2005) found learners self-allocate well on almost-known items but poorly on novel ones. When telemetry shows camping on too-easy or too-hard material, override toward the band.

## When NOT to apply

- **Learner is in first-exposure encoding for a high-element-interactivity concept** — There is no stable expected-correct probability before a mental model exists; targeting a band on noise produces frustration. Build the model with worked examples ([worked-example-effect](../01-learning-science/worked-example-effect.md)) and faded practice ([faded-worked-examples](../04-delivery-patterns/faded-worked-examples.md)); switch to band sequencing once a working schema exists.
- **Item pool is uncalibrated** — Without `b`/`a` parameters or usable proportion-correct statistics, the runtime cannot estimate p(correct) and "70-85%" is a wish, not a rule. Calibrate, fall back to ordinal difficulty bands, or use fixed-form delivery (see [item-difficulty-discrimination](../07-runtime-decisions/item-difficulty-discrimination.md)).
- **Pure motor skill acquisition phase** — The 85% rule was derived for categorical decision tasks and generalizes poorly to motor execution. Apply band logic to declarative/conceptual companion items (torque values, sequence checks); leave the motor reps to coaching rules.
- **Learner is overwhelmed at any difficulty** — When pre-assessment or session telemetry shows saturation (slow responses, basics errors, expressed frustration), the band is the wrong control surface. Reduce extraneous load, restore a worked example, then re-enter band sequencing after stabilizing.
- **Context demands content coverage over precision on a single trait** — A certification blueprint may require visiting subdomains regardless of fit; the band selector then runs inside content-balancing constraints rather than dominating the schedule.

## How to apply

- **Estimate p(correct) for every candidate before selecting** — Use IRT `P(θ̂)` (see [item-difficulty-discrimination](../07-runtime-decisions/item-difficulty-discrimination.md)), BKT (Corbett & Anderson, 1995; see [bayesian-knowledge-tracing](../07-runtime-decisions/bayesian-knowledge-tracing.md)), or rolling per-skill accuracy; rank by closeness to the 0.70-0.85 band; pick the highest-information admissible item inside it.
- **Set the band asymmetrically around the goal** — For acquisition, weight toward 0.75-0.85 (faster learning rate, fewer demoralizing errors). For mastery decisions, tighten to 0.80-0.85 near the cut. For [productive-failure](../04-delivery-patterns/productive-failure.md), drop briefly to 0.50-0.65 by design — only inside a return path, not as steady state.
- **Use a 5-10 item rolling window for drift detection** — Single-item accuracy is too noisy; 5-10 attempts smooth enough to react without lag. Up-step at ≥0.90 sustained, down-step at ≤0.55 sustained.
- **Step difficulty by one granularity unit, not a free jump** — Whether granularity is an IRT half-logit, a difficulty tier, or a complexity level in a worked example, change one notch per drift event. Multi-notch jumps over- or under-shoot the band and induce oscillation.
- **Fade scaffolds inside the band, not as a separate process** — Each in-band success is also a signal to remove the next layer of support (cue, partial worked example, hint ladder). Van de Pol et al. (2010) argue fading without contingency is the most common scaffolding error.
- **Re-estimate after every response, not on a schedule** — A single unexpected response can flip the band membership of the next-best item, especially when the learner model is imprecise. Queueing "the next three items" up front collapses the rule to fixed-form delivery.

## Common misapplications

- **Treating the ZPD as a fixed target rather than a function of the current estimate** — The band moves as the learner improves; an item in-band at session start may be too easy two responses later. The runtime updates the target with the estimate, not with the calendar.
- **Forcing the band on first-exposure material** — Wood et al. (1976) and Chaiklin (2003) both emphasize that support precedes contingent fading; demanding 70-85% accuracy on a concept the learner has not yet encoded produces guessing, not learning.
- **Conflating self-reported confidence with model-estimated p(correct)** — Metcalfe and Kornell (2005) found judgments-of-learning correlate with item position relative to mastery but are systematically biased; use them as complements, not substitutes.
- **Setting the band too tight (e.g., 80-85% only)** — Tight bands collapse to a small high-discrimination subset and over-expose those items. The 70-85% range balances band membership against pool diversity and exposure control ([item-difficulty-discrimination](../07-runtime-decisions/item-difficulty-discrimination.md)).
- **Holding the band constant across all skills** — A learner near mastery on Skill A and at first-exposure on Skill B needs different rules at the same moment. Per-skill state ([bayesian-knowledge-tracing](../07-runtime-decisions/bayesian-knowledge-tracing.md)) drives per-skill band selection.
- **Reading "85%" as a goal accuracy rather than a target probability for the next item** — Wilson et al. (2019) derived 85% as the optimal training error for the upcoming attempt, not an end-state criterion. Mastery cuts (often 0.95) live in [mastery-thresholds](../07-runtime-decisions/mastery-thresholds.md); 0.85 is the moving selection target, not the finish line.

## Examples across domains

**Avionics — adaptive practice block during a Garmin GTN 750 install training module.**

*Setup.* A technician has completed the worked-example pass on pinout interpretation for the
GTN 750 and is entering supervised practice. The system holds an IRT-style ability estimate
`θ̂ = +0.10` for "pinout interpretation" with SEM 0.45. The calibrated pool contains 60
items with `b` ranging from -1.5 to +1.8.

*Selection.* The runtime computes p(correct | `θ̂`) for each candidate and screens to the
0.70-0.85 band — at `θ̂ = +0.10` this is items with `b` in roughly -0.65 to +0.50. From the
12 admissible items, it picks the one with highest discrimination `a` not yet served and
not exposure-capped: a connector-grounding scenario at `b ≈ 0.0, a ≈ 1.5`, p(correct) ≈ 0.78.
The technician answers correctly. After 5 in-band responses (4 correct, rolling accuracy 0.80),
the runtime detects no drift and continues. After two more correct attempts, rolling accuracy
hits 0.86 and the runtime steps `θ̂` upward, shifting the admissible band to `b ∈ -0.4 to +0.7`.
A scaffolded "show pin numbers next to the diagram" cue that supported the prior items is
faded — the next item omits it.

*Decision.* When the technician approaches the module's mastery cut (`p(known) = 0.90` per the
BKT model on this skill), the runtime tightens the band to 0.80-0.85 estimated correct at
items with `b` near the cut, and the final 4 items decide pass/fail at the high-precision
edge of the ability scale (see [item-difficulty-discrimination](../07-runtime-decisions/item-difficulty-discrimination.md)).

**Culinary apprenticeship — an apprentice working knife skills and mise-en-place sequencing
under a sous-chef in a working brigade kitchen.**

*Setup.* A first-year apprentice has watched the sous-chef demonstrate brunoise (2-mm dice)
and julienne, completed two guided reps each, and is moving into self-paced practice on
prep for the evening service. The chef's tutor app holds running per-skill estimates: knife
control `θ̂ = -0.20` (early), mise-en-place sequencing `θ̂ = +0.30` (closer to ready).

*Selection.* For knife control, the band targets items where the apprentice can succeed
about 75-80% of the time: a brunoise on a soft pepper rather than a dense celeriac, with
the chef checking dimensional consistency on a 5-piece sample. The first-exposure
contraindication holds for a new cut entirely (chef demonstrates mirepoix the first time
through worked example, not by setting the apprentice on a target accuracy). For mise-en-place
sequencing, where the apprentice is closer to ready, the runtime serves a four-station
sequencing decision under timed pressure — p(correct) ≈ 0.80 — and pulls back the
"sequence-card on the rail" scaffold once three consecutive in-band successes register,
matching contingent fading (Van de Pol et al., 2010).

*Decision.* When rolling accuracy on knife control rises to 0.90+ across a five-rep window,
the runtime steps difficulty (denser vegetable, tighter dimensional tolerance, or smaller
target dice) by one notch — not two — and resets the rolling window. When it falls below
0.55 (e.g., the apprentice attempts brunoise on celeriac and misses dimensional consistency
on three of five), the runtime drops to a softer vegetable and surfaces a re-demonstration
prompt rather than continuing to push (see
[error-analysis-corrective-feedback](../04-delivery-patterns/error-analysis-corrective-feedback.md)).

## Quality signal

The ZPD selector is working when (a) at least 70% of served items land within the
0.70-0.85 expected-correct band on a 10-item rolling window, (b) observed accuracy on
those items tracks predicted accuracy within ±0.10, and (c) drift events trigger
single-notch difficulty steps with no oscillation across the next 5 items. Persistent
miss of the band, predicted-vs-observed gaps above 0.15, or repeated up-down-up steps
signal an undersized or miscalibrated pool, an unstable per-skill estimate, or a
learner-state contraindication that the runtime should surface to the instructor.

## Cross-references

- See [item-difficulty-discrimination](../07-runtime-decisions/item-difficulty-discrimination.md) for the IRT machinery the band selector calls into.
- See [bayesian-knowledge-tracing](../07-runtime-decisions/bayesian-knowledge-tracing.md) for per-skill p(known) estimates that drive per-skill band selection.
- See [mastery-thresholds](../07-runtime-decisions/mastery-thresholds.md) for the cut-score logic the band tightens around for pass/fail decisions.
- See [desirable-difficulties](../01-learning-science/desirable-difficulties.md) for the broader framework — the ZPD band is one operationalization of "make it harder than easy, easier than failing".
- See [expertise-reversal](../01-learning-science/expertise-reversal.md) for why the band moves up as expertise accrues and worked-example support shifts to retrieval.
- See [faded-worked-examples](../04-delivery-patterns/faded-worked-examples.md) for the scaffold-fade pattern that lives inside the contingency rule.
- See [productive-failure](../04-delivery-patterns/productive-failure.md) for the deliberate sub-band excursion that targets generative struggle, not steady-state difficulty.
- See [sm2-fsrs](../07-runtime-decisions/sm2-fsrs.md) for the spacing scheduler that pairs with band-targeted item selection on the timing axis.
