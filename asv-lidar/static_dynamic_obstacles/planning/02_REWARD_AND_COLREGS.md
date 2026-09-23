# 02 — Reward Function and COLREGs Encoding

> **Status note (2026-09-22).** Parts of this document are superseded by the implementation, which is frozen as **baseline-v1** (`configs/baseline_v1.json`, git tag `baseline-v1`). The current statement of the method is `planning/METHODS_BRIEF.md`. Superseded here:
>
> - Turn sense: the own ship gives way to a crossing target from either side and turns toward its side (A17); head-on starboard, overtaking port.
>
> - Rule 17: only 17(a)(i) course-keeping is rewarded; an earlier 17(a)(ii) release is open (A30).
>
> - Term definitions and weights: see `02a` as amended below, and `METHODS_BRIEF.md` §5.
>
> The rationale below still stands where it is not listed. `F..` = `PROJECT_STATE.md`, `A..` = `OPEN_PROBLEMS.md`.

**Revision 2** — Rules 13–16 with Rule 9 precedence; Rule 17 active release removed.
**Handover target:** Claude chat (design), then Claude Code
**Depends on:** nothing — **start here.** The precedence table produced in §3 gates the
encounter classifier in 01, the reward terms below, and the width sweep in 04
**Carry in:** `REWARD_REDESIGN.md` (the existing 6-term specification)

---

## 1. Purpose

Extend the 6-term reward redesign to cover a dynamic target and COLREGs Rules 8, 9 and
13–16, without recreating the scale failure found in Paper 2.

**Confirmed (D2):** compliance is enforced through **reward terms plus an explicit
encounter-class feature** in the observation — not shaping alone, not a separate
arbitration or safety-filter layer.

---

## 2. Why this mechanism

Pure continuous shaping is fragile because the rule is **discrete and conditional**: which
rule applies depends on relative bearing and heading-intersection sectors, so a smooth
reward cannot express a class switch cleanly.

A separate arbitration or safety-filter layer would give hard guarantees but breaks the
end-to-end framing and moves the interesting behaviour out of the learned policy.

**Chosen middle path:** classify the encounter deterministically each step (module defined
here, implemented in 01), then apply a **class-conditional** penalty. The discontinuity
lives in a classifier under your control rather than in learned features.

Precedent: Waltz & Okhrin include the encounter situation directly in the observation
vector *and* condition their COLREGs reward on it — useful cover when a reviewer asks
whether the agent is being handed the answer.

---

## 3. Rule precedence — the blocking deliverable

**This table is contribution N2 and it gates everything downstream.**

In a narrow channel Rule 9 modifies the others:

- 9(a) — keep to the starboard side of the fairway
- 9(b), 9(d) — do not impede vessels that can navigate only within the channel
- 9(e) — special overtaking provisions

Applying Rule 14's "both alter to starboard" in a channel too narrow to permit it will be
caught by any reviewer who knows COLREGs. Rule 15 crossing geometry is likewise partly
inapplicable where there is no room to cross.

### 3.1 The always-give-way simplification

**Own ship gives way in all crossing encounters, justified by Rule 9(b)** — a vessel under
20 m shall not impede the passage of a vessel that can safely navigate only within a
narrow channel.

This deliberately replaces the Rule 18 route used by Meyer et al. (2020), where the own
ship is always give-way because it is significantly smaller than the vessels encountered.
That premise fails here: own ship and target are similarly sized model vessels, so the
asymmetry Rule 18 requires does not exist, and claiming it in simulation then validating
against an identical vessel is an inconsistency a reviewer will find.

### 3.2 Precedence table (structure resolved)

**The organising principle: Rule 9 constrains the available space; Rule 8(e) supplies the
action when that space is unavailable.**

| Encounter | Wide channel | Narrow channel | Governing | Fallback when inadmissible |
|---|---|---|---|---|
| Head-on | Alter to starboard | Hold starboard side; 9(a) compliance satisfies 14 without alteration | 14 + 9(a) | Slacken speed, 8(e) |
| Crossing | Give way — alter to starboard or pass astern | Give way if room exists | 15, 16 + 9(b) | Slacken speed or stop, 8(e) |
| Overtaking | Pass either side | **Pass to port of target** | 13 + 9(a), 9(e)\* | Hold astern at reduced speed, 8(e) |
| Being overtaken | Hold course and speed | Hold course and speed, keep starboard | 13 + 17(a)(i) + 9(a) | — |

\* Geometric constraint only. Rule 9(e) requires sound signals and the overtaken vessel's
agreement, which the platform cannot provide. **State this as an explicit scope limitation** —
cheap to acknowledge, awkward if a reviewer finds it first.

**Head-on rationale.** Rule 9(a) already requires both vessels to keep to the starboard side
of the fairway. If both comply, a port-to-port pass occurs without either altering course, so
Rule 14 is satisfied by channel-keeping rather than by an evasive manoeuvre. An alteration is
required only when the target is not where 9(a) says it should be. This is what happens in
practice and it makes Rule 9 precedence concrete rather than abstract.

**Overtaking side.** Follows from 9(a): if the overtaken vessel keeps to its starboard side,
the room is on its port side, so overtaking means altering **to port**.

Width thresholds remain open — they are an output of the Study 1 sweep (04 §5), not an input.
The table structure is complete, which is what 01 and the reward terms were waiting on.

Define "narrow" **geometrically** — in ship breadths, and in terms of the lateral excursion
the compliant manoeuvre requires — never by reference to where a method fails. The
threshold at which each transition occurs is itself a result, produced by the width sweep
(Study 1, doc 04).

Krasowski & Althoff (2024) is the model for formalising this into checkable
specifications.

---

## 4. Reward structure

### 4.1 Carried from `REWARD_REDESIGN.md`

Six terms — re-verify each against the new observation, since `c_t` no longer contains
borders:

1. Exponential clearance-based collision-avoidance term
2. Unified path-following term
3. Border penalty
4. Progress term
5. Action-smoothness penalty
6. Existence cost

Terminal: collision −200, goal +100, timeout via value bootstrapping.

**The border penalty now draws on the boundary branch and the geometric boundary, not on
LiDAR returns.** Confirm the term still behaves as designed.

### 4.2 COLREGs terms — five classes

| Term | Condition | Intent |
|---|---|---|
| Wrong-side passing | any class with a defined passing side | Penalise passing on the incorrect side |
| Port turn in head-on | head-on, TCPA > 0 | Penalise altering to port |
| Bow crossing | crossing, overtaking | Penalise crossing ahead of the target |
| Course-keeping hold | being overtaken | Reward holding course and speed |
| Late or insufficient action | give-way classes | Rule 8 |

**Removed in Revision 2:** the stand-on release term. Active release under Rule 17(a)(ii)
is out of scope (S5). Only 17(a)(i) passive course-keeping survives, as the
course-keeping hold term above.

**Implementation trap — port turns are not globally bad.** The head-on term penalises altering
to port, but overtaking in a narrow channel *requires* altering to port (§3.2). Class-conditional
gating handles this in principle, but it is exactly the kind of thing that gets miscoded into a
global "port turns are penalised" term. Assert it in a unit test.

**Use yaw rate, not rudder angle, as the turn criterion.** Ship dynamics delay the sign
change in yaw rate by several timesteps after a rudder reversal, so rudder angle is a poor
proxy for whether the vessel is actually turning — more so for an underactuated model
vessel than for a full-scale ship.

### 4.3 Rule 8 — early and substantial

Rule 8(b) requires alterations large enough to be readily apparent and that a succession of
small alterations be avoided. Encode as:

- Penalty on late first action, measured against TCPA at action onset
- Penalty on small first action magnitude
- **Check the tension:** the existing action-smoothness term discourages oscillation, but
  must not also suppress the large single alteration Rule 8 requires. These pull in
  opposite directions and the balance needs explicit verification

### 4.4 Speed as a legal action — RESOLVED, and it has consequences

**Decision: when compliance would push the vessel into the channel boundary, the agent
slackens speed or stops under Rule 8(e) rather than violating the boundary.** The boundary
remains a hard constraint; Rule 8(e) is the admissible response.

**Propulsion authority must widen.** This closes the open question. An agent that cannot slow
down cannot comply. Verify whether the Bluefin can reverse thrust — if it can only reduce
forward thrust, "take all way off" is unavailable and the paper should say so rather than
claim it.

**Critical tension: the progress term and existence cost fight this.** Both penalise slowness,
and Rule 8(e) compliance requires exactly that. A class-conditional carve-out is needed —
suspend or attenuate the progress penalty while the agent is in a compliant slow-down.
Without it, the reward actively punishes the behaviour being taught.

**Degenerate-policy risk.** Loosen the progress penalty and the obvious exploit is to creep
along slowly forever, trivially avoiding everything and never finishing. Gate the carve-out on
(a) an encounter class being active and (b) CRI above threshold. Inspect the trained policy's
speed profile in open stretches as an acceptance check.

**Upside for Study 1.** As the corridor narrows, expected behaviour transitions from *alter
course* to *slacken speed*. That transition is a behavioural result, not merely a degradation
curve, and it is a considerably stronger figure than a success-rate decline.

**New metric:** speed-reduction events, their timing, and whether the class and geometry made
them appropriate.

---

## 5. Magnitude hierarchy

Enforced by design, not emergent from tuning:

```
collision  ≫  border  ≫  COLREGs violation  ≫  path following  ≫  smoothness
```

A COLREGs-compliant collision is worse than a non-compliant near-miss.

---

## 6. Scale audit protocol

**Mandatory. The direct lesson from Paper 2.**

The `r_oa` term was ~49× weaker than `r_pf` at contact distance, making the λ weighting
effectively 98/2 rather than the stated 50/50 — masked entirely by the weighting framing
and invisible until audited.

1. Normalise every term to a known, stated range before weighting
2. Instrument the environment to log **per-term episode-integrated contribution**, not
   instantaneous values
3. Run a random policy and the Paper 2 SAC baseline through the new reward; tabulate
   effective contribution per term
4. Verify the empirical ordering matches §5. If not, the coefficients are wrong regardless
   of what the ratios say on paper
5. Repeat after any coefficient change

Report the table in the paper (Table R7 in the draft skeleton).

---

## 7. Ablation design

**Not optional.** Paper 2 conceded the component-wise ablation because each variant would
have required a separate multi-seed campaign. The two-vessel cut roughly halves compute,
which is what makes this affordable now.

Primary 2 × 2:

|  | Encounter feature OFF | Encounter feature ON |
|---|---|---|
| **COLREGs terms OFF** | Avoidance only | Told, not rewarded |
| **COLREGs terms ON** | Learned from kinematics | Full method |

Leave-one-out on individual COLREGs terms, five seeds each.

**Framing note.** An explicit class feature means part of the behaviour is given rather
than learned. Get ahead of it: the classifier supplies the rule *regime*, the policy learns
the *manoeuvre*, and the 2 × 2 quantifies the split. This is also closer to how a
watchkeeper operates.

---

## 8. Open items

- ~~Produce the precedence table~~ — **structure resolved (§3.2)**. Width thresholds remain
  open but are an output of Study 1, not an input
- Verify whether the vessel can reverse thrust (§4.4)
- Design the progress-penalty carve-out and its gating conditions (§4.4)
- Re-verify the six carried-over terms against the new observation, especially the border
  penalty
- Check the Rule 8 / smoothness tension explicitly (§4.3)
- Set per-term normalisation ranges before any coefficient tuning
