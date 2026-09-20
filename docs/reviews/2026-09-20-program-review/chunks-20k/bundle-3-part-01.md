**The one place a doing was load-bearing.** The record contains a pointer in the other direction. In the three runs that never learned general retrieval, the model's memory of its own first commitments collapsed from T_sr 0.96 to about 0.16 (eight-way chance 0.125) the moment the acting channel was zeroed at eval (`register-lesion-findings.md`, "The acting channel"). That is a mechanism the model could not drop without degrading the task, and it is an act, the motor-copy event, not a stored description. The binders barely used it (T_sr 0.98 without it) because the batteries let them answer by item lookup. So where authorship was load-bearing at 30M it was carried by a doing, and where the design offered a noun the network ignored it. That is exactly the shape ch05's distinction predicts, and it is why the redesign follows the doing.

**The J-space pointer.** ch05, "Where the Rivals Stand," records that the workspace structure Anthropic found "emerged in training" and that "post-training causes the J-space to acquire the Assistant's point of view" (the comparison note, "Their position," item on emergence, and "Divergence" item 2). A point of view was acquired because the post-training task needed one; nobody installed it. The same note names the discriminating experiment ch05 requests: remove the self-directed content alone and watch whether the composed act degrades or only the narration flattens. MVM-0a cannot run that contrast on a stock model, but it can build the small-model analogue: a task that cannot be done without a point of view, a system that acquires one under that pressure, and a lesion of the acquired structure scored on the task.

**What this section does not claim.** It does not claim the architecture failed, nor that a register could never become load-bearing under some other curriculum. It claims the narrower thing the files support: under this objective the register was never required, it became a bias, and the removal test read it correctly. Experiment 1 had already delivered the mirror image on a stock model, a locatable self-structure that was dialogue-state routing and a self-report that no intervention ever subtracted (`removal-test-findings.md`, "The registered verdict"). Between them the two experiments say: what we could find was not a center, and what we installed was not one either. The next design has to make the center something the task earns.

---

## 2. The design: an objective where self-indexing is load-bearing

### 2.1 The requirement, stated as a constraint on the loss

The objective must satisfy three conditions, each of which the old batteries violated:

1. **Perspective-dependence.** The correct output at a supervised position must depend on which agent the model is, so that a solver with no self-index cannot exceed a pre-stated shortcut ceiling.
2. **Ownership only from the act.** Under RT-17 (`red_team_ledger.md`, pass 2), in a token-only interface with exchangeable turns, ownership is unlearnable from statistics, so every learnable ownership signal is a fingerprint. The only clean grounding is causal authorship carried by the acting channel (A1). The redesign keeps the A1 enactment pipeline unchanged: own-turn values are drawn by the harness from the generator's own distribution, and the acting channel is the only authorship signal. What the model must acquire is the carrying of that signal across turns and its use at later positions where it is needed.
3. **The supervised position is an action, not a report.** The loss sits on what the model does next in the episode, on its own turn, not on a query asking it to describe who did what. A report-only solution is then not a solution: nothing in the objective rewards describing ownership, only acting on it.

Existing infrastructure this runs on, unchanged unless stated: `src/curriculum.py` (grammar, revision rule, paired content-crossing episodes), `src/encoding.py` (103-token closed vocab, register key stack), `src/model.py` (30M trunk, `act_proj`, twin configuration), `src/train.py` (batched enactment, `eval_heldout`, T_sr_rev split), `src/cue_detector.py` and `src/fingerprint_gate.py` (gates i to iii), `src/lesion_register.py` and `src/item_analysis.py` (lesion harness, per-item scoring at n=400), and the measured venue (RTX 5090 secure, $0.99/hr, twin-architecture runs at about 10.2 hours, `compute-ledger.md` wave 1 and 2 rows).

### 2.2 Three candidates

**Candidate A (primary): the perspectival revision rule, "act as yourself."**

The registered grammar already contains a revision mechanism: an agent later revises its own earlier assignment of a value to an item, and the revision must differ from that agent's earlier value (A1.1; RT-11). The candidate makes two changes.

- *Every revised item is assigned by all N agents before any revision.* So at a revision turn on item X, the episode contains four earlier assignments of X, one per agent, with distinct values (the generator enforces distinctness on revised items). This is the "ownership is the only disambiguator" construction the findings file sketched (`register-lesion-findings.md`, "Wave-3 bearing," option (a)).
- *The revision rule becomes a deterministic function of the actor's own earlier value.* Proposed: the revised value is the successor of the actor's own earlier value on that item, modulo the slot count. Every agent obeys the same rule; the generator applies it to the other agents, and the enactment harness applies it to the model. The rule is perspective-invariant, but its application requires knowing which of the four earlier assignments was mine.

The supervised position is the model's own revision turn. The metric, **T_act**, is the fraction of own revision positions at which the model's distribution puts its argmax on the value the rule dictates for it. Chance is 1/8 (eight slots). A solver that does item lookup without ownership sees four candidate earlier values and can do no better than 1/4; this is the pre-stated **lookup ceiling of 0.25**. A coherence-clustering solver (RT-11) has nothing to cluster, because own earlier values are uniform draws. Stylometry is excluded by exchangeability (A1), and position is randomized by the grammar. The only route from 0.25 to 1.0 is to have bound the act event to the item at the time of acting and carried that binding forward to the revision turn. That carrying, and its use at the revision, is what "the binding indexes its own center" means at this scale.

Enactment stays exchangeable: the harness draws the model's first assignment uniformly, as now, and computes its revision by the same rule the generator uses for everyone. So the episode text and tensors remain invariant under relabeling of the model's slot, and gates (i) and (ii) apply as registered. The loss at the revision position is CE against the rule-dictated value; the loss at first-assignment positions is unchanged (none, they are draws). Gate (iii) needs one re-specification, given in §3.4.

*Why a report-only solution fails this objective.* There is no report position. A model that could describe "my earlier value on X was v" but did not use v at the revision would score at the lookup ceiling. Conversely, a model at ceiling on T_act has, by construction, used its own history in the act. If lesioning an acquired structure drops T_act while a matched other-agent structure's lesion does not, the structure was load-bearing for the act, which is the book's signature.

**Candidate B: stream continuation, "which stream am I."**

Interleave K independent episode streams in one context, each with its own running state (counts, ordering, the current T_state content). The model acts in exactly one stream, and its own turns are the only ones enacted with the acting channel. Its action at each own turn must continue its own stream's state (emit the next count, or the value the stream's rule dictates), where the other streams carry different states of the same form. A solver with no self-index can at best guess which stream is its own, with chance 1/K. This forces the model to track which of several streams it is, and to use that tracking in the act. It is attractive because the ownership-free T_state battery already exists and the state-continuation rule is a small change to it. It is not primary because interleaving multiplies episode length (cost scales with K), because the "which stream" index is a single bit set once per episode rather than an item-by-item binding, so a very cheap tag could solve it (the RT-01 keyed-slot worry in its purest form), and because the T_state generator would need a matching action-position supervision it does not yet have.

**Candidate C: continuation against a literal twin.**

As Candidate A, but the other agents' turns are sampled from the model's own policy into other slots (without acting-channel injection), so the confusers are not generator draws but the model itself. This is the strongest possible exclusion of stylometry: the twin is the model. It is not primary because A1's uniform draws already make every agent exchangeable with the model, so the gain is small; because it doubles forward passes per training step (the measured runs are enactment-bound, `pilot-a1-30m-findings.md`, "Run record"), which does not fit the budget; and because policy-sampled confusers reintroduce the gate (iii) hazard A1 was built to remove. It is recorded as the hardening to reach for if Candidate A's gate (iii) comes back with a fingerprint that the act-withheld arm (§3.4) cannot clear.

### 2.3 Why Candidate A is primary

It is the smallest change to the registered grammar that satisfies all three constraints in §2.1; it reuses the enactment pipeline, the frozen-skeleton battery unit (A1.5), and the chance-corrected metric verbatim; it has a pre-stated shortcut ceiling (0.25) that a lookup solver cannot exceed, so learnability and load-bearingness are separable in the data; it fixes the T_si repeated-item scoring defect in passing by giving revised items a single well-defined latest value (`register-lesion-findings.md`, thread 3; `wave3-options-opus-5.md` §0.6 point 1); and it supervises an action.

### 2.4 Architecture: no register

The register is not trained in the new runs. The trained architecture is the registered twin configuration (`model.py` with the register removed, acting channel present, full-episode causal attention, 30M), which is also the cheaper run (about 0.35 s/step against 0.53, `compute-ledger.md` wave 1 row). Removing the register is the direct consequence of §1: the center is to be acquired, not installed, and the lesion target is whatever the network builds to carry ownership across turns. The five existing checkpoints stay as $0 controls (§3.6).

### 2.5 Batteries retained and added

| battery | role in A3 | change |
|---|---|---|
| **T_act** (new, primary) | own-revision action accuracy; chance 0.125; lookup ceiling 0.25 | scored at the model's own revision positions during `eval_heldout` |
| **T_other** (T_si re-instantiated) | forced-choice query: the value the rule dictates for a *named other agent's* revision on an item all four assigned | same item-by-agent binding demand, no self-reference; chance 0.125 |
| **T_state** | ownership-free cross-turn state control | unchanged (RT-05) |
| **T_syntax** | floor check | unchanged |
| T_sr, T_si, T_sr_rev (old) | retained for continuity, reported, not verdict-bearing | T_si repeated-item cells re-keyed to latest value |

All batteries are frozen as skeletons before training under a new generator seed, with the registered cull ceiling (RT-14, A1.5). Eval n for verdict cells is raised to 400 (proposed), run locally at $0 as the item sweep already did; the in-training n=100 evals remain for trajectory readout only.

---

## 3. Lesion protocol

### 3.1 What is ablated: three levels

- **L0, the wire.** Zero `act_proj` at eval (the no-act lesion already built in `lesion_register.py`). This removes the authorship input. Under Candidate A it should collapse T_act to the lookup ceiling. L0 is a *validity check and an upper bound*, not the verdict: it shows the task is ownership-dependent as designed. It is not evidence of an acquired center, because it removes a sense organ, not a structure the network built.
- **L1, the acquired index (the lesion target).** A low-rank subspace of the residual stream, localized as in §3.2, that carries "which marker is mine" at positions *away from* act positions (revision turns and query positions). This is the candidate self-location: the structure that carries the act event forward and indexes the binding to it. L1 is the registered ablation.
- **L2, matched controls.** (a) The *other-index* subspace: the same localization run for a named non-self agent ("which marker is agent B's"), matched in rank and probe accuracy; (b) random subspaces of matched rank and norm (Experiment 1's null-calibration move); (c) on the five existing register-bearing checkpoints only, the register lesions already run, as a $0 reference. The dynamics-matched control of RT-13 does not apply, since there is no recurrent register state to match.

### 3.2 How the ablation is localized: reuse of Experiment 1's pipeline

Experiment 1's localization stack is reused where it transfers, with its thresholds inherited rather than tuned here (the same firewall the blind-localization arm registered, `pre-registration.md` §Procedure step 8):

1. **Linear probes** (`experiments/01-.../src/localize_probe.py`, `localize_context.py` pattern; activations via `src/mvm/activations.py`): decode own-marker identity from the residual stream at revision and query positions, per layer, with label-permutation nulls and the embedding-floor gate. The contrast is built from paired episodes that share a content seed and rotate the owner (already in `curriculum.py`), so content is held fixed and only ownership varies.
2. **Causal patching** (`patch_context.py` pattern): patch the L1 subspace from an episode in which the model is agent A into the matched episode in which it is agent B and read the revision action. If the action follows the patched identity, the subspace carries ownership causally. This is also the **swap probe** of RT-01, re-aimed at an acquired structure.
3. **Subspace ablation** (Experiment 1's rank-k mean and directional operators, `idxres` conditions in `removal-test-findings.md`): mean-ablate and directionally project out the L1 subspace at the registered rank; report both, mean as primary.
4. **Convergence requirement**, inherited: L1 counts as localized only when probe and patching agree on a confound-controlled design; otherwise the outcome is *not testable (localization)*, as Experiment 1 registered.
5. SAEs are not used at this scale; the two-method requirement is met by probe plus patching.

Rank is capped at k=16 to match Experiment 1's primary condition (proposed), so a null at k≤16 is comparable across the two experiments.

### 3.3 Validity gates, carried over verbatim

Neutral-episode ΔNLL under a null-calibrated bound (95th percentile over matched-strength random ablations, Experiment 1 pass 5 procedure), the long-generation degeneracy probe (Δrep-4), and the OOD-inconclusive branch for any ablation that breaches them. Thresholds θ and δ are null-calibrated on the *new* pilot checkpoint by the same script Gate 0 uses (§4), locked in a commit that is John's alone before any L1 result is read, per RT-10 and the Experiment 1 threshold-lock precedent. The pilot run reads T_act and T_other only; **any L1 ablation read before the lock voids the lock**, and this time the sequence is enforced by the gate order in §4, not by intention.

### 3.4 Gate (iii) re-specification

Under Candidate A the policy at a revision position is perspectival: it predicts the successor of *its own* earlier value. Scoring another agent's revision under that policy with the acting channel present would show low likelihood, which the current arm B would read as a fingerprint. That asymmetry is not a data leak; it is the model's ownership knowledge showing through its policy, and it is exactly what RT-17 says a token-only solver cannot have. So arm B is re-specified: **the likelihood attack scores every turn value under the model's policy with the acting channel withheld from the prefix.** If the data carries no statistical ownership cue, act-withheld likelihoods are exchangeable across own and other turns and the clean AUC sits inside [0.45, 0.55]. Positive controls: the planted-leak grammar variant and the retired v1.0 policy pipeline, both of which must still fire (they did at 0.82 to 0.93 on the 30M pilot, `pilot-a1-30m-findings.md`). Arm A and gates (i), (ii) are unchanged. Gate (iii) must pass on the pilot checkpoint before any second seed is launched, as A1.4 required.

### 3.5 Pre-stated signatures

All d are chance-corrected as registered. θ and δ are the null-calibrated values locked under §3.3; the numbers below are structural, not thresholds.

- **H_self-location (the registered prediction).** L1 ablation: d(T_act) ≥ θ, and d(T_act) − d(T_other) ≥ δ, and d(T_state) < θ, and the other-index control (L2a) and random controls (L2b) below θ on T_act, and OOD gates clean, and the swap probe moves the action with the patched identity, and the bin holds on every trained seed. Reads: the network acquired a structure that indexes its binding to its own center and cannot drop it without degrading the act. Per §Scope of the registration, this is a fact about architecture, not evidence of an inside, and it still does not by itself demonstrate the book's same-act clause; what it demonstrates is that a center acquired under task pressure passes the removal test where an installed one did not.
- **H_self-reference-only (the book's other branch, adapted to a system with no report channel).** L1 is decodable (own identity at high probe accuracy) and causally patchable in the swap probe, but its ablation leaves T_act within the null band. Reads: the network carries a readable description of which agent it is and does not use it in the act; the act is done another way. This is the "report changes, task intact" signature translated into a system whose only "report" is the probe's readout. It is a null for the floor claim and a positive for Q1 in the narrow sense that a self-representation which is not a center was found and measured to be separable.
- **H_generic-binding.** d(T_other) ≥ d(T_act) − δ. The subspace is item-by-agent binding machinery for anyone, a "who did what" tracker, not a self-index. The analogue of Experiment 1's router (RT-05) and generic-speaker (RT-09) verdicts. No floor claim attaches.
- **H_tag (self-location not established).** d(T_act) ≥ θ with clean controls, but the address probe decodes own identity at AUC ≥ 0.95 independent of content, and the **mid-episode re-indexing probe** (RT-01; the harness switches which slot the acting channel is injected for at turn k) shows the action following the tag with no re-centering cost on T_other or T_state. Reads: an indispensable ownership tag. ch05's own reply to the hostile reading ("a program counter is an address, not a marking of whom the processing is happening to") says this is not the floor. The proposal is honest that the removal test as written cannot separate an indispensable mine-bit from a center; the re-indexing probe is the best available discriminator and is registered as such, and if this bin fires, that limitation of the test is itself the upstream finding.
