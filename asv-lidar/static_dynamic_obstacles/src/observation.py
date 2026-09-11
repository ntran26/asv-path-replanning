"""Observation assembly: five branches, 56 dims, one dynamic target.

**Revision 2** — one target slot with a presence bit.  Supersedes the
three-slot-plus-mask-vector version.

The index order of every element is frozen in `OBSERVATION_SPEC.md`.  Every
checkpoint and every frozen evaluation case depends on it, so change it only
with a deliberate version bump -- never by editing a loop here.

    branch      contents                                   dims
    lidar       c_t sector closeness, obstacles only         27
    boundary    virtual boundary raycast, normalised          7
    ego         u, v, r                                       3
    path        e_y, chi_tilde, chi_tilde_LA                  3
    target      15 features + 1 presence bit                 16
                                                       total 56

Slot management (01 §6.2)
-------------------------
* **One target slot.**  `N_MAX_TARGETS` is a config parameter and the branch is
  built as an indexed slot, so a multi-vessel extension costs a retrain rather
  than a redesign (S1).  The machinery below is parameterised but not exercised
  at 1.
* **Track-ID persistence.**  The slot is bound on first acquisition and held
  until track loss, so observation discontinuities coincide with real events
  rather than with re-sorting.  CRI-based ordering is moot at one target, but
  the hook stays for the extension path -- when slots are contested, the
  highest-CRI targets hold them.
* **Presence bit, not a mask vector.**  Zero-padding alone is unsafe: zero is a
  legitimate value for bearing and for relative speed, so a zero-padded empty
  slot reads as a target sitting on top of the vessel on a matching course.

**No-target coverage.** A meaningful fraction of training episodes must carry no
target at all, or the static-only configuration is out of distribution.  That is
enforced by the scenario distribution (`cfg.NO_TARGET_EPISODE_PROB`), not here.
"""

from __future__ import annotations

import math
from typing import Dict, List, Optional, Sequence

import numpy as np
from gymnasium.spaces import Box, Dict as DictSpace

import constants as cfg
import encounter as enc
from colregs.context import ContextManager, EncounterContext
from tracking import Track

# Per-slot feature layout.  Documented in OBSERVATION_SPEC.md; this tuple is the
# machine-readable copy and the two must agree.
SLOT_FEATURE_NAMES = (
    "distance_to_domain",        # 0
    "bearing_sin",               # 1
    "bearing_cos",               # 2
    "ct_sin",                    # 3
    "ct_cos",                    # 4
    "target_speed",              # 5
    "relative_speed",            # 6
    "dcpa",                      # 7
    "tcpa",                      # 8
    "cri",                       # 9
    "class_none",                # 10
    "class_head_on",             # 11
    "class_crossing",            # 12
    "class_overtaking",          # 13
    "class_being_overtaken",     # 14
    "presence",                  # 15
)
assert len(SLOT_FEATURE_NAMES) == cfg.TARGET_FEATURES
PRESENCE_INDEX = SLOT_FEATURE_NAMES.index("presence")
CLASS_SLICE = slice(10, 15)

# Which slot features can meaningfully *saturate a normaliser*, as opposed to
# sitting at +/-1 because that is what the quantity is.
#
# `bearing_sin/cos` and `ct_sin/cos` reach +/-1 whenever the target is dead
# ahead or on a reciprocal course -- which is the head-on geometry this paper is
# about, so they are at their bounds constantly and correctly.  The class
# one-hot and the presence bit are indicators.  Counting any of them as clipping
# reported a 55% clip rate on a branch whose normalised features were healthy,
# and buried the one that was not.
#
# What is left is the five clipped normalisers plus `cri`.  `cri` stays in
# deliberately: it is bounded by construction rather than clipped, but a risk
# index pinned at 1.0 carries no gradient in exactly the regime that matters
# most, and that is worth seeing.
NORMALISED_SLOT_FEATURES = (
    "distance_to_domain", "target_speed", "relative_speed",
    "dcpa", "tcpa", "cri",
)
NORMALISED_SLOT_INDICES = tuple(SLOT_FEATURE_NAMES.index(n)
                                for n in NORMALISED_SLOT_FEATURES)


def branch_feature_names(branch: str) -> tuple:
    """Human names for one branch's dimensions, for the panel's drill-down."""
    if branch == "lidar":
        return tuple(f"sector{i}" for i in range(cfg.LIDAR_SECTORS))
    if branch == "boundary":
        return tuple(f"bnd{b:+.0f}" for b in cfg.BOUNDARY_BEARINGS_DEG)
    if branch == "ego":
        return ("u", "v", "r")
    if branch == "path":
        return ("e_y", "chi", "chi_LA")
    if branch == "target":
        return tuple(f"{name}" for _ in range(cfg.N_MAX_TARGETS)
                     for name in SLOT_FEATURE_NAMES)
    return ()

TARGET_DIM = cfg.N_MAX_TARGETS * cfg.TARGET_FEATURES
OBS_DIM = cfg.LIDAR_SECTORS + cfg.BOUNDARY_RAYS + 3 + 3 + TARGET_DIM
assert OBS_DIM == 56, OBS_DIM


def observation_space() -> DictSpace:
    """The frozen observation space.  Five branches, 56 dims."""
    return DictSpace({
        "lidar": Box(0.0, 1.0, shape=(cfg.LIDAR_SECTORS,), dtype=np.float32),
        "boundary": Box(0.0, 1.0, shape=(cfg.BOUNDARY_RAYS,), dtype=np.float32),
        "ego": Box(-1.0, 1.0, shape=(3,), dtype=np.float32),
        "path": Box(-1.0, 1.0, shape=(3,), dtype=np.float32),
        "target": Box(-1.0, 1.0, shape=(TARGET_DIM,), dtype=np.float32),
    })


# ---------------------------------------------------------------------------
# Per-slot features
# ---------------------------------------------------------------------------
def slot_features(ctx: EncounterContext) -> np.ndarray:
    """The 16 values for one occupied slot, in the frozen order.

    **A pure read of the `EncounterContext`.**  Until T4 this recomputed the
    bearing, the CPA products and the risk from the track, which meant the
    observation and the reward each derived the same encounter from the same
    inputs by their own route.  01 §5.3 asks for one module and two consumers;
    two consumers computing the same thing separately satisfies the letter of
    that and not the point of it -- they would diverge at a threshold eventually,
    and the agent would be penalised for a role it was never shown.

    Angles go in as sin/cos so the wraparound at +/-180 deg is not a
    discontinuity the network has to learn around.
    """
    a = math.radians(ctx.alpha)
    c = math.radians(ctx.ct)

    kinematics = np.array([
        np.clip(ctx.d_domain / cfg.D_SCALE, 0.0, 1.0),
        math.sin(a),
        math.cos(a),
        math.sin(c),
        math.cos(c),
        np.clip(ctx.speed_ts / cfg.SPEED_SCALE, 0.0, 1.0),
        np.clip(ctx.v_rel / cfg.SPEED_SCALE, 0.0, 1.0),
        np.clip(ctx.dcpa_domain / cfg.DOMAIN_RADIUS_DCPA, 0.0, cfg.DCPA_CLIP_DOMAINS)
        / cfg.DCPA_CLIP_DOMAINS,
        np.clip(ctx.tcpa, -cfg.TCPA_CLIP, cfg.TCPA_CLIP) / cfg.TCPA_CLIP,
        np.clip(ctx.cri, 0.0, 1.0),
    ], dtype=np.float32)

    presence = np.ones(1, dtype=np.float32)
    return np.concatenate([kinematics, enc.one_hot(ctx.cls), presence]).astype(np.float32)


# ---------------------------------------------------------------------------
# Slot management
# ---------------------------------------------------------------------------
class SlotManager:
    """Maps track ids to fixed observation slots, holding assignments stable.

    At `N_MAX_TARGETS = 1` this reduces to "the first track acquired keeps the
    slot until it is lost".  The contention path below is the extension hook
    (S1) and is not exercised in the two-vessel scope.
    """

    def __init__(self, n_slots: int = cfg.N_MAX_TARGETS) -> None:
        self.n_slots = int(n_slots)
        self.reset()

    def reset(self) -> None:
        self._slot_of: Dict[int, int] = {}
        self._track_in: List[Optional[int]] = [None] * self.n_slots

    @property
    def assignments(self) -> Dict[int, int]:
        return dict(self._slot_of)

    def occupant(self, slot: int) -> Optional[int]:
        return self._track_in[slot]

    def update(self, tracks: Sequence[Track], risks: Sequence[float]) -> Dict[int, int]:
        """Assign slots for this step and return {track_id: slot}.

        Held assignments survive; free slots go to the highest-risk unassigned
        targets; a full board is contested only when a newcomer out-ranks the
        weakest occupant.
        """
        live = {t.id for t in tracks}

        # Release slots whose track is gone.
        for tid in [tid for tid in self._slot_of if tid not in live]:
            self._track_in[self._slot_of.pop(tid)] = None

        risk_of = {t.id: float(r) for t, r in zip(tracks, risks)}
        unassigned = sorted((t for t in tracks if t.id not in self._slot_of),
                            key=lambda t: risk_of[t.id], reverse=True)

        for track in unassigned:
            if None in self._track_in:
                slot = self._track_in.index(None)
            else:
                # Contest the weakest occupant, and take the slot only if this
                # target is genuinely riskier.
                weakest = min(self._slot_of, key=lambda tid: risk_of.get(tid, 0.0))
                if risk_of[track.id] <= risk_of.get(weakest, 0.0):
                    continue
                slot = self._slot_of.pop(weakest)
                self._track_in[slot] = None

            self._slot_of[track.id] = slot
            self._track_in[slot] = track.id

        return dict(self._slot_of)


# ---------------------------------------------------------------------------
# Assembly
# ---------------------------------------------------------------------------
class ObservationBuilder:
    """Builds the Dict observation from the shared per-step encounter contexts.

    **The builder owns the `ContextManager`, and the reward reads it back.**
    That is the single-object arrangement 02a §10.1 asks for, arranged so there
    is one place it can be computed: the observation cannot be assembled without
    the contexts, so they always exist and are always the ones the reward sees.
    An arrangement where the reward built its own would satisfy `01 §5.3` on
    paper and fail it in practice.

    The environment passes the map-side arguments (`path`, `boundary_polygon`,
    `s_along`, `true_targets`) straight through, because it is the only object
    holding both the perception output and the map.  Callers that supply none of
    them -- unit tests exercising the perceived half -- get contexts whose
    admissibility is permissive and flagged as unknown.
    """

    def __init__(self, n_slots: int = cfg.N_MAX_TARGETS) -> None:
        self.slots = SlotManager(n_slots)
        self.contexts = ContextManager()
        self.n_slots = int(n_slots)
        self._last: Dict[int, EncounterContext] = {}

    def reset(self) -> None:
        self.slots.reset()
        self.contexts.reset()
        self._last = {}

    @property
    def encounters(self):
        """The hysteretic classifier, for callers that held a reference to it."""
        return self.contexts.classifier

    @property
    def encounter_contexts(self) -> Dict[int, EncounterContext]:
        """`{track_id: EncounterContext}` as of the last `build`.

        The reward's only input about the targets.  Returned by reference, not
        copied: the contexts are read within the same step they were built and
        copying eight floats per target per step to protect against a mutation
        nobody makes is not a trade worth making.
        """
        return self._last

    @property
    def encounter_classes(self) -> Dict[int, str]:
        """`{track_id: class}` as of the last `build`."""
        return {tid: ctx.cls for tid, ctx in self._last.items()}

    @property
    def crossing_sides(self) -> Dict[int, str]:
        """`{track_id: "port"|"starboard"|"none"}` as of the last `build`.

        Not in the observation -- Rule 9(b) makes the own ship give way from
        either side, so the side is not a different obligation -- but 02a §6.4's
        passing-side term needs the geometry.
        """
        return {tid: ctx.crossing_side for tid, ctx in self._last.items()}

    def build(self, *, sector_closeness, boundary_scan, u: float, v: float,
              yaw_rate_degps: float, cross_track_error: float,
              course_error_deg: float, lookahead_course_error_deg: float,
              tracks: Sequence[Track] = (), p_os=(0.0, 0.0), v_os=(0.0, 0.0),
              heading_os_deg: float = 0.0,
              r_path: float = 0.0, path=None, boundary_polygon=None,
              s_along=None, true_targets: Sequence = (),
              open_water: bool = False) -> Dict[str, np.ndarray]:
        """Assemble one observation, building this step's contexts as it goes."""
        contexts = self.contexts.update(
            tracks=tracks, p_os=p_os, v_os=v_os, heading_os_deg=heading_os_deg,
            u_os=float(u), r_path=float(r_path), path=path,
            boundary_polygon=boundary_polygon, s_along=s_along,
            cross_track=float(cross_track_error), true_targets=true_targets,
            open_water=open_water,
        )
        self._last = contexts

        assignment = self.slots.update(
            tracks, [contexts[t.id].cri for t in tracks])

        slot_block = np.zeros((self.n_slots, cfg.TARGET_FEATURES), dtype=np.float32)
        for tid, slot in assignment.items():
            slot_block[slot] = slot_features(contexts[tid])

        span = max(cfg.MAP_WIDTH, cfg.MAP_HEIGHT)
        return {
            "lidar": np.asarray(sector_closeness, dtype=np.float32),
            "boundary": np.asarray(boundary_scan, dtype=np.float32),
            "ego": np.array([
                np.clip(u / cfg.SPEED_SCALE, -1.0, 1.0),
                np.clip(v / cfg.SPEED_SCALE, -1.0, 1.0),
                np.clip(yaw_rate_degps / 180.0, -1.0, 1.0),
            ], dtype=np.float32),
            "path": np.array([
                np.clip(cross_track_error / span, -1.0, 1.0),
                np.clip(course_error_deg / 180.0, -1.0, 1.0),
                np.clip(lookahead_course_error_deg / 180.0, -1.0, 1.0),
            ], dtype=np.float32),
            "target": slot_block.reshape(-1).astype(np.float32),
        }


def split_target(target) -> tuple:
    """Split the `target` branch into (slot features, presence bits).

    The single place that knows the layout, so the environment, the features
    extractor and any analysis script all agree.
    """
    arr = np.asarray(target, dtype=np.float32)
    slots = arr.reshape(*arr.shape[:-1], cfg.N_MAX_TARGETS, cfg.TARGET_FEATURES)
    return slots, slots[..., PRESENCE_INDEX]
