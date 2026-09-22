from __future__ import annotations

import asyncio
import copy
import json
import logging
import math
import time
import uuid
from datetime import datetime, timezone
from pathlib import Path
from typing import Optional

from .agent import Agent
from .action_validator import validate
from . import agenda
from . import interruptions
from .perception import VisionPerceiver
from . import cell_sweep
from . import dead_end
from .cell_sweep import filter_survey_claims
from .landmarks import merge_entries, scan_landmarks
from . import map_capture
from . import move_plan
from . import places_manifest
from . import planner
from . import place_visuals
from . import recognition
from . import route_map
from . import route_planner
from . import sim_run
from . import stand_point
from . import survey_mission
from .episodic_memory import EpisodicLog
from .memory_store import _MOVEMENT_ACTIONS, movement_summary, movement_trace
from .place_db import (COMMUNITY_SURVEY_MAX_AGE_SECONDS, PLACE_EXTENT_CM,
                       PlaceDB, yaw_to_compass)
from .social_memory import SocialMemory, is_anonymous
from .spatial_memory import SpatialMap
from .world_clock import WorldClock
from .world_grid import WorldGrid

logger = logging.getLogger("AgentRuntime")

# A frontier cell is only blocked after this many consecutive failed walk
# attempts — unless the avatar is already adjacent, which is proof enough.
_MAX_FRONTIER_FAILURES = 3

# A survey may not capture a cell from outside it, so it walks to that cell —
# and a cell walled off by scenery would otherwise retry that walk forever. It
# gets this many travel ticks; a leg that moves less than a tenth of a step is
# not progress. Exhausting them abandons the survey and blocks the cell.
# How many legs of the breadcrumb trail the APC carries. Long enough to walk
# back out of a multi-leg detour, short enough that old ground stops mattering.
_BREADCRUMB_LEN = 8

_MAX_SURVEY_TRAVEL_TICKS = 4
_SURVEY_TRAVEL_PROGRESS_CM = 150.0

# Wake/new-place survey: absolute UE yaws for the four cardinal views. These
# labels and yaws are geographic, not relative to the avatar's initial facing.
_SWEEP_VIEWS = [
    ("N", 270.0),
    ("S", 90.0),
    ("E", 0.0),
    ("W", 180.0),
]

# walk_to direction → yaw offset from current facing.
_DIRECTION_YAW_OFFSET = {
    "forward": 0.0,
    "forward-left": -45.0,
    "forward-right": 45.0,
    "left": -90.0,
    "right": 90.0,
    "back": 180.0,
}

# walk_to direction → absolute UE yaw, independent of which way the avatar
# happens to be pointing (#56). Everything else the APC reasons with — the
# survey headings, the compass observations in PlaceDB, the grid — is already
# cardinal; facing-relative words were the only part that silently changed
# meaning underneath the model, so they are no longer the only option.
_ABSOLUTE_DIRECTION_YAW = {
    "east": 0.0, "southeast": 45.0, "south": 90.0, "southwest": 135.0,
    "west": 180.0, "northwest": 225.0, "north": 270.0, "northeast": 315.0,
}

def _cell_label(grid: dict | None) -> str:
    """The one name a cell has when we speak to the model: "col,row" (#59).

    ``WorldGrid.locate`` returns two different names for the same cell — ``key``
    is the raw signed index from the world origin ("-3,0"), ``col``/``row`` are
    0-based from the grid's min corner ("6,6"). Both were being shown, so SR39
    has Dufus reasoning about "cell -3,0" while the decision log, the survey
    messages and PlaceDB all recorded "6,6" for the ground under his feet.
    ``col,row`` wins because every durable store already keys on it; ``key``
    stays internal to SpatialMap. Out-of-bounds cells keep the raw key — a real
    position outside the authored grid is better said than swallowed.
    """
    grid = grid or {}
    if grid.get("col") is not None and grid.get("row") is not None:
        return f"{grid['col']},{grid['row']}"
    return str(grid.get("key", "?"))


def _compass_word(dcol: int, drow: int) -> str:
    """The compass word for a cell offset: +col is east, +row is south.

    Grid rows count down from the min-y corner, so a cell with a larger row index
    is further south — the same convention ``_ABSOLUTE_DIRECTION_YAW`` encodes and
    the one every survey heading already used. Sign only; the caller carries the
    distance separately, because "northeast, 3 cells" is two facts and squashing
    them into one word is how a bearing turns into a route.
    """
    vertical = "north" if drow < 0 else "south" if drow > 0 else ""
    horizontal = "east" if dcol > 0 else "west" if dcol < 0 else ""
    return f"{vertical}{horizontal}" or "here"


# Compass reversal — "the way I came" is the opposite of the way I travelled.
_OPPOSITE_COMPASS = {
    "N": "S", "NE": "SW", "E": "W", "SE": "NW",
    "S": "N", "SW": "NE", "W": "E", "NW": "SE",
}

# Compass letter (yaw_to_compass, crumbs, survey headings) → the direction word
# the prompt and _direction_places speak in (#77).
_COMPASS_LETTER_WORD = {
    "N": "north", "NE": "northeast", "E": "east", "SE": "southeast",
    "S": "south", "SW": "southwest", "W": "west", "NW": "northwest",
}

# A cached "what my eyes saw down that heading" is a fact about one spot, not
# about the world — it goes stale the moment the body leaves the spot (#77).
_EYES_VALID_CM = 300.0

# Whether an aging survey makes a cell surveyable again (user, 2026-08-19:
# "stop surveying what we have already done ... turn it off"). Off: a cell
# with any composite is done ground; re-surveying becomes a deliberate,
# user-triggered act (#39/#35), never an ambient one.
SURVEY_STALE_REFRESH = False

# One movement "step" for direction-relative walks (cm). This is the NOMINAL
# step now, not the only one: `move_plan.plan_step` shrinks it toward whatever
# must not be walked into and grows it across ground the shared map has already
# proven (#86). It stays the fixed answer to the *map* question "which cell lies
# one step that way", which must not move because the body's step got shorter.
_STEP_DISTANCE = 1500.0

# How finely the move plan walks the line ahead (#86). The sample spacing is the
# plan's precision floor — a coarse scan reports the last CLEAN sample, so it
# stops the step further short of a refusal than it needs to, and short steps
# cost paid ticks. 1.5 m over a 90 m scan is 60 samples of arithmetic against an
# in-memory patch list, with each cell looked up once. That is free.
_SCAN_STEP_CM = 150.0

# How far the move plan ASKS along a heading before sizing a step (#89/#90).
#
# The travel probe (`_AHEAD_TRACE_CM`, 5 m) answers a different question — "is
# something about to stop me" — which is why it is short and why a hit inside it
# may WAKE cognition. Lengthening it would wake a paid decision for every wall
# down a corridor. Two questions, two probes.
#
# This one asks the whole question: *how far can this body travel that way*. It
# is deliberately the largest step we would ever take, because the answer is the
# STEP — not a limit on a constant. In a town the sweep almost always strikes
# something well inside it, and that distance is what the APC then walks.
_PLAN_PROBE_MAX_CM = 9000.0

# Where to aim the body-box probe when the body does not fit straight ahead
# (#88). The raster cannot answer this: its columns are offset by the capsule
# RADIUS, so the whole scan is exactly as wide as the body and "far left" means
# 34 cm. SR49 had Dufus told `open=none` by a dumpster with clear pavement a
# metre either side, and he bounced 30 m back and forth for fourteen ticks.
# Turning the probe asks the question he actually needs answered — "would my
# body fit if I went THAT way" — and the engine rotates the capsule sweep with
# it, so the answer is a real fit test and not a guess from rays.
_OPEN_HEADING_OFFSETS = (-90.0, -45.0, 45.0, 90.0)

# Radar (#92). The sweep above has two limits that together made entrapment
# inevitable, and neither is about reasoning:
#
#   1. It covers a quarter turn either side of the face. The ground BEHIND the
#      body is never measured. SR51 logged "open headings: none — boxed in"
#      three times; each of those means "none of the four in front of me", and
#      the way out was behind him, unmeasured, every time.
#   2. It fires only after `fits is False` — after the body has already walked
#      into the thing. It is a collision response, not a sense.
#
# The radar answers the same question on all eight compass headings on EVERY
# decision tick. Walk into a throat and the ring closes in front of you tick by
# tick while the way out behind you is still open and still measured, so there
# is nothing to predict and nothing to bail out of.
#
# Range is a room-sized read, deliberately longer than one nominal step (15 m):
# what tells an alcove from a square is the SHAPE of the ring, and that only
# shows up past where the next step would land.
_RADAR_RANGE_CM = 2000.0
# #103: how close the body must get to a measured stand point before the
# survey starts shooting. Tight on purpose — the whole point is standing THERE.
_STAND_POINT_ARRIVE_CM = 200.0
_RADAR_HEADINGS = ("N", "NE", "E", "SE", "S", "SW", "W", "NW")
# UE yaw: 0 = +X = East, 90 = South, 180 = West, 270 = North.
_COMPASS_ABS_YAW = {"E": 0.0, "SE": 45.0, "S": 90.0, "SW": 135.0,
                    "W": 180.0, "NW": 225.0, "N": 270.0, "NE": 315.0}
_WORD_ABS_YAW = {_COMPASS_LETTER_WORD[k]: v for k, v in _COMPASS_ABS_YAW.items()}

# Walking a grown step (#86). The engine is never handed a target further than
# one nominal step, so the navmesh has almost no room to route around something
# and land somewhere else — SR47's 45 m orders arrived 50 m sideways. The hops
# in between are walked with NO model call: crossing ground the map already
# proved is not a thing worth thinking about, which is the whole reason the step
# is allowed to grow.
_LEG_ARRIVE_CM = 250.0        # close enough to this hop to order the next one
_LEG_DRIFT_CM = 700.0         # off the straight line by this much: stop, think
_WALK_PLAN_MAX_TICKS = 12     # a plan may never outlive this, whatever happens

# A walk that ends more than this far off the heading it asked for did not go
# where it was sent: the engine walked a navmesh PATH around something, not the
# straight line the order named. Reported as a fact, never corrected for.
_HEADING_DRIFT_DEG = 45.0
_HEADING_DRIFT_MIN_CM = 300.0   # below this the direction of travel is noise

# The body-box probe (#81) traces along the avatar's FACING. Its clearance may
# only cap a step heading within this much of that facing — a clearance measured
# east says nothing about walking north, and applying it anyway would shorten
# every sideways step for a wall it was never looking at.
_PROBE_HEADING_TOLERANCE_DEG = 45.0

# When the camera view is unchanged AND the avatar is standing still, re-decide
# every Nth tick anyway so a stopped agent is always re-prompted to move to the
# next grid/place — without freezing (view never changes) or spamming the LLM
# (an intentionally-idle agent still only decides once every N stationary ticks).
_STATIONARY_REDECIDE_TICKS = 4

# Stuck detection (live path): the engine can report ai_state="moving" while the
# avatar is wedged against an un-navmeshed obstacle (a parked van) and making no
# real progress. After this many consecutive "moving but didn't advance" ticks we
# flag it stuck — force a fresh decision and tell the LLM to pick another direction.
_STUCK_PROGRESS_CM = 100.0   # min cm advanced per tick to count as real progress
_STUCK_TICKS = 3             # consecutive no-progress moving ticks → stuck
_STUCK_TRACE_CM = 300.0      # forward raycast distance when stuck (cm)
_MOVEMENT_START_CM = 10.0    # ignore tiny pose jitter when timing first displacement
_PROGRESS_NOISE_CM = 200.0   # route distance-to-goal jitter below this reads as "no change"

# Wedge budget (#65). A stall is ordinary; a *run* of stalls is the failure mode
# that eats whole runs — SR39 four ticks on one spot, SR40 eight. At this many
# consecutive stalled orders the sense stops being one line among many and names
# the proven way out explicitly. Deliberately a louder FACT, not a code-side
# override: what to do about it stays the model's call.
_WEDGE_BUDGET_TICKS = 3
# Surfaces an APC should be walking on — the same set its rules name. A cell
# recorded with one of these has been *walked*, not merely seen, so it is a
# proven escape rather than a guess from the picture.
_GOOD_FOOTING = ("pavement", "road", "dirt_path")

# How many frontier cells to name (#73). Enough to show there is a choice and
# that it has a shape; not so many the list reads as a route to follow.
_FRONTIER_LIMIT = 4

# Path sense (B7): while traveling, watch what is directly ahead so the agent
# can step around people/vehicles instead of walking through them — pawn-vs-pawn
# collision is invisible to the navmesh, so this is the cognitive loop's problem,
# not an engine steering feature. Only *mobile* categories interrupt travel;
# structures ahead are ordinary navmesh business (corners, walls) and would spam.
_AHEAD_TRACE_CM = 500.0      # forward raycast distance while traveling (cm)
_MOBILE_BLOCKERS = {"person", "animal", "vehicle"}

# Personal space (B7b): the decision cadence (~9 s/tick) is far too slow to stop
# a walk once someone is close — by the next tick the agent is in their face. So
# inside this standoff the lizard brain halts the walk itself (a motor reflex,
# like flinching — not a decision) and reports the halt as a fact; the forced
# re-decide then lets the LLM choose: talk, step around, continue. 300 cm is
# roughly where a whole person fills the first-person camera frame.
_STANDOFF_CM = 300.0

# Don't re-greet (#12.1): once an agent has spoken with someone, suppress the
# "you may greet a known person" interrupt for this many sim-minutes so they
# don't say hi every tick the person stays in view. A fresh encounter after the
# cooldown (or a new sim-day) greets again.
_GREET_COOLDOWN_MINUTES = 60
_NEARBY_CHARACTER_CM = 2500.0
# Speech carries about this far (#45). Wider than the 300 cm standoff so a
# greeting reaches someone approaching, narrower than sighting range so an APC
# across the district does not overhear a conversation.
_HEARING_CM = 1200.0
_MAX_UTTERANCES = 20                # bounded scrollback; speech is ephemeral
_PLACE_ROAM_MARGIN_CM = 100.0

# Semantic classifier for forward-trace hits.
# Maps engine actor names/classes → generic categories the LLM can reason about.
# The lizard brain translates engine noise; it does NOT infer meaning or advise action.
# SR45 evidence (2026-08-19, #61): the trace fires and hits — 42 hits in one run —
# but the level's real actor names never matched this table. `veh_SportClassic_2`
# is a parked car and fell through to "obstacle"; so did `shopFront_01`,
# `road_sign_11`, and three `pose_standing_*` crowd figures. The engine's naming,
# not a guess: `veh_` prefixes vehicles, `shopFront` fronts buildings,
# `pose_standing_*` are SkeletalMeshActor crowd props (a real APC is `APC_<id>_BP_C_n`).
_BLOCKER_KEYWORDS: list[tuple[set[str], str]] = [
    ({"van", "car", "truck", "vehicle", "veh_", "bus", "taxi", "auto",
      "tractor", "trailer", "motorcycle", "bike"}, "vehicle"),
    ({"apc_", "npc", "character", "pedestrian", "civilian", "thirdperson",
      "person", "human"}, "person"),
    # Person-shaped scenery that will never move or answer. Its own category on
    # purpose: calling it "person" would invite the APC to greet a mannequin.
    ({"pose_standing", "pose_sitting", "mannequin", "crowd", "statue"}, "figure"),
    ({"dog", "cat", "animal", "bird", "creature", "pet"}, "animal"),
    ({"wall", "building", "shopfront", "storefront", "house", "fence", "barrier",
      "door", "gate", "pillar", "column", "porch", "stair", "roof"}, "structure"),
    ({"sign", "post", "pole", "mailbox", "hydrant", "bench", "crate", "barrel",
      "bin", "trash", "planter", "rock", "boulder"}, "prop"),
    ({"corn", "cornfield", "crop", "wheat", "foliage", "bush", "hedge", "shrub",
      "tree", "vegetation"}, "foliage"),
]

# #83: engine-side identity, ordered most-deliberate first. A tag is the level
# author SAYING what a thing is; an asset name is just a file name they typed.
_TAG_CATEGORIES: dict[str, str] = {
    "vehicle": "vehicle", "car": "vehicle", "truck": "vehicle",
    "person": "person", "npc": "person", "apc": "person", "character": "person",
    "figure": "figure", "mannequin": "figure", "crowd": "figure",
    "animal": "animal",
    "structure": "structure", "building": "structure", "wall": "structure",
    "prop": "prop", "clutter": "prop", "streetfurniture": "prop",
    "foliage": "foliage", "vegetation": "foliage", "crop": "foliage",
}

# Physical materials are set by the art pipeline, not by whoever named the asset,
# so they survive a rename and a marketplace pack.
_PHYS_MATERIAL_CATEGORIES: list[tuple[set[str], str]] = [
    ({"flesh", "skin", "body"}, "person"),
    ({"foliage", "grass", "leaf", "crop", "corn", "wheat"}, "foliage"),
    ({"cartire", "carbody", "vehicle", "chassis"}, "vehicle"),
    ({"brick", "concrete", "plaster", "drywall", "stucco"}, "structure"),
]

def _classify_blocker(actor_name: str, actor_class: str, signals: dict | None = None) -> str:
    """Generic category for a probe contact — engine signals first, names last (#83).

    Substring-matching ``GetActorLabel()`` is not object detection; it is reading
    the level author's file names and hoping. SR45 proved it: three whole name
    families (``veh_*``, ``shopFront*``, ``pose_standing_*``) fell through at once.
    So the order is deliberate — an author's *deliberate* statement outranks an
    author's *incidental* one:

      1. explicit actor tags        — the author saying what a thing IS
      2. pawn-ness                  — the engine knowing this thing is a body
      3. physical material          — set by the art pipeline, survives renaming
      4. component / collision hints
      5. the keyword table          — last resort, and it says so when it fires

    ``signals`` is the identity block from ``forward_volume`` (physical_material,
    component_class, collision_profile, tags, is_pawn, is_movable). Absent, this
    degrades to the pre-#83 name matching, which is what the old single-ray probe
    still supplies.
    """
    signals = signals or {}

    # 1. Tags — the only channel where the author states meaning rather than
    #    incidentally encoding it in a file name.
    for tag in signals.get("tags") or []:
        category = _TAG_CATEGORIES.get(str(tag).strip().lower())
        if category:
            return category

    # 2. The engine knows a pawn from a prop. A real body is never scenery.
    if signals.get("is_pawn"):
        return "person"

    # 3. Physical material, set by the art pipeline.
    phys = str(signals.get("physical_material") or "").lower()
    if phys:
        for keywords, category in _PHYS_MATERIAL_CATEGORIES:
            if any(kw in phys for kw in keywords):
                return category

    # 4. Component and collision hints. A SkeletalMesh that cannot move is
    #    person-shaped scenery — the crowd mannequins — and must NOT read as a
    #    person, or an APC will try to greet one.
    component = str(signals.get("component_class") or "").lower()
    profile = str(signals.get("collision_profile") or "").lower()
    if "vehicle" in profile:
        return "vehicle"
    if "skeletalmesh" in component and signals.get("is_movable") is False:
        return "figure"

    # 5. Last resort: the level author's file names.
    text = (actor_name + " " + actor_class).lower()
    for keywords, category in _BLOCKER_KEYWORDS:
        if any(kw in text for kw in keywords):
            return category

    # Fail loud (rule 12): an unclassified contact is still reported as a generic
    # obstacle — never dropped — but everything known about it is logged so the
    # gap is visible instead of silently degrading.
    logger.info(
        f"blocker classifier: nothing matched actor '{actor_name}' "
        f"(class '{actor_class}', material '{phys or '?'}', component "
        f"'{component or '?'}', profile '{profile or '?'}', "
        f"tags {list(signals.get('tags') or [])}) — reported as generic obstacle"
    )
    return "obstacle"


def _loc_xyz(loc) -> tuple[float, float, float] | None:
    """Coerce a location payload ({x,y,z} dict or [x,y,z] list) to a float triple."""
    if isinstance(loc, dict):
        return float(loc.get("x", 0)), float(loc.get("y", 0)), float(loc.get("z", 0))
    if isinstance(loc, (list, tuple)) and len(loc) >= 3:
        return float(loc[0]), float(loc[1]), float(loc[2])
    return None


def _yaw_of(rotation) -> float | None:
    """Extract yaw (degrees) from a rotation payload ({x:pitch, y:yaw, z:roll} or [pitch, yaw, roll])."""
    if isinstance(rotation, dict) and rotation.get("y") is not None:
        return float(rotation["y"])
    if isinstance(rotation, (list, tuple)) and len(rotation) >= 2:
        return float(rotation[1])
    return None


def _open_columns(volume: dict) -> tuple[list[str], bool]:
    """Which columns of the body-box raster are a gap the body could use (#81).

    The engine's own ``open_columns`` counts a column open when ANY of its three
    rows is clear. SR47 shows why that is the wrong test: a sedan sat 17 cm into
    Dufus's ``far_right`` column at body height, the row above it was clear, and
    the prompt told him the gap was on his far right. A column is a gap only when
    NOTHING in it is struck.

    The second return value is the honest "we do not know". When the capsule says
    the body does not fit and no raster cell was struck at all, the obstacle
    passed between the rays — the scan cannot name a side, and claiming all five
    are open (which is what SR47 printed for ``paint_set_10``) is worse than
    admitting it saw nothing.
    """
    cells = volume.get("cells") or []
    if not cells:
        return list(volume.get("open_columns") or []), False
    blocked = {c.get("column") for c in cells if c.get("blocked")}
    order = ["far_left", "left", "centre", "right", "far_right"]
    seen = [c.get("column") for c in cells]
    columns = [c for c in order if c in seen]
    openings = [c for c in columns if c not in blocked]
    silent = bool(volume.get("fits") is False and not blocked)
    return (([] if silent else openings), silent)


def _offset_location(x: float, y: float, z: float, yaw_deg: float, distance: float) -> list[float]:
    """World location `distance` cm from (x, y) along world yaw (UE: X forward, yaw toward +Y).

    Components are snapped to the nanometre. ``cos(270 deg)`` is -1.8e-16, not
    zero, so a due-north step from a position sitting exactly on a cell boundary
    lands a hair west of it and resolves to the *neighbouring* cell — harmless
    while this only previewed cells, and not harmless now that a refusal filed
    against the wrong cell is durable and shared (#59).
    """
    rad = math.radians(yaw_deg)
    return [x + round(math.cos(rad) * distance, 6),
            y + round(math.sin(rad) * distance, 6), z]


class AgentManager:
    def __init__(
        self,
        worlds_dir: Path,
        llm_router,
        unreal_bridge,
        memory_store,
    ):
        self.worlds_dir = worlds_dir
        self._agents_dir: Path | None = None
        self.llm = llm_router
        self.bridge = unreal_bridge
        self.memory = memory_store

        self.agents: dict[str, Agent] = {}
        self.running = False
        self.paused = False
        self.tick_seconds = 1
        self.mode = "survey"                      # "survey" = build the grid; "play" = live on it (#102)
        self._sim_task: Optional[asyncio.Task] = None
        self._tick_count = 0
        self._started_at: float | None = None
        self._last_tick_duration = 0.0
        # Every path that can observe/decide/act shares this gate: the automatic
        # loop, POST /tick, and POST /agents/{id}/tick. The active label is set
        # synchronously before acquiring the lock so competing requests return
        # busy immediately instead of queueing behind a long LLM call.
        self._tick_lock = asyncio.Lock()
        self._active_tick_entry: str | None = None

        # Explore-mode state (per agent).
        self.perceiver = VisionPerceiver()
        self._spatial: dict[str, SpatialMap] = {}   # agent_id -> loaded map (cache)
        self._social_mem: dict[str, SocialMemory] = {}  # agent_id -> acquaintance store (cache)
        self._episodic_log: dict[str, EpisodicLog] = {}  # agent_id -> episodic event log (cache)
        self._cell_sweeps: dict[str, dict] = {}      # agent_id -> in-progress unexplored-cell sweep
        self._survey_abandons: dict[str, dict] = {}  # agent_id -> why the last survey travel was abandoned (#101)
        self._mission_complete: set[str] = set()     # agent_ids whose survey mission found no work left (#96)
        self._last_cell: dict[str, str] = {}        # agent_id -> previous cell key, for nav edges
        self._frontier_failures: dict[str, dict[str, int]] = {}  # agent_id -> cell key -> consecutive failed walks
        self._scene_skips: dict[str, int] = {}      # agent_id -> consecutive scene-unchanged skips (gate liveness)
        self._nearby_ids: dict[str, frozenset[str]] = {}  # agent_id -> nearby APC ids on prior cheap sample
        # #81: set once if the engine cannot answer the body-box probe, so the
        # fallback warning is loud but printed once rather than every tick.
        self._volume_probe_unavailable = False
        # #92: same idea for the one-trip radar command. An un-rebuilt plugin
        # simply does not have it, and the eight-sweep fallback is correct — so
        # this is a speed degradation, not a sense degradation, and it says so.
        self._radar_command_unavailable = False
        self._last_pos: dict[str, tuple] = {}       # agent_id -> last (x, y), for stuck detection
        self._travel_from: dict[str, tuple] = {}    # agent_id -> (x, y) at the previous observation
        self._travel: dict[str, dict] = {}          # agent_id -> last real heading travelled (#56)
        self._breadcrumbs: dict[str, list[dict]] = {}  # agent_id -> recent legs walked (#58)
        self._last_order: dict[str, dict] = {}      # agent_id -> last movement ordered, for the achieved-vs-ordered check (#59)
        self._walk_plans: dict[str, dict] = {}      # agent_id -> grown step being walked hop by hop (#86)
        self._tried_here: dict[str, dict] = {}      # agent_id -> {at, tried: {heading: moved_cm}} while wedged on one spot (#60)
        self._stall_run: dict[str, int] = {}        # agent_id -> consecutive stalled orders (#65)
        self._walls: dict[str, list[dict]] = {}     # agent_id -> volumes the body has proved impassable (#91)
        self._last_raster: dict[str, float] = {}    # agent_id -> last probe blocked_fraction, sets seal width (#91)
        self._last_ground: dict[str, dict] = {}     # agent_id -> {ground_under_feet, nearest_ground} from the last radar (#101)
        self._footing_recoveries: dict[str, int] = {}  # agent_id -> lifetime count of footing reflex recoveries (#101)
        self._no_progress: dict[str, int] = {}      # agent_id -> consecutive "moving but didn't advance" ticks
        self._last_grid_place: dict[str, tuple] = {}  # agent_id -> (grid, place), reported even when LLM skipped
        self._routes: dict[str, dict] = {}          # agent_id -> place target and path progress
        self._live_pos: dict[str, dict] = {}        # agent_id -> {x,y,yaw} last observed (#18 live map)
        self._utterances: list[dict] = []           # recent speech, deliverable to hearers (#45)
        self._heard_seq: dict[str, int] = {}        # agent_id -> last utterance id consumed (#45)
        self._utterance_seq = 0                     # monotonic id so nobody hears a line twice
        self._movement_timing: dict[str, dict] = {} # agent_id -> wake/first-walk/displacement clocks (#20)
        self._eyes: dict[str, dict] = {}            # agent_id -> {at, views: {compass_word: seen-ahead}} at the current spot (#77)
        self._bounces: dict[str, dict] = {}         # agent_id -> {cell: times walked in and straight back out} this run (#26)
        self._force_next_decide: set[str] = set()   # agents owed one full cognition tick (e.g. survey just resolved)

        # Fixed per-level grid; reloaded with the level in _load_agents.
        self.world_grid = WorldGrid()

        # In-world clock; reloaded with the level, anchored at start_simulation.
        self.world_clock = WorldClock()

        # SQLite place cell store — initialised in start_simulation once world dir is known.
        self.place_db: PlaceDB | None = None

        # Run-log file handler (#51) — attached in start_simulation, detached on
        # stop so the file is closed (Windows can't delete an open log file).
        self._run_log_handler: logging.FileHandler | None = None

        # Sim run tag (SR<n>) — allocated per-world in start_simulation, pushed to
        # the bridge (observation filenames) + memory (decision log) for attribution.
        self.sim_run_id: str = "SR0"

        # Agents whose first schedule step of this run has passed. Only that
        # first step may seed a missing scheduled place as the agent's own
        # place cell (wake-time initialization) — cleared per run.
        self._wake_stepped: set[str] = set()

        # True when this world has a places.json (WP6): the wake seed then
        # warns — an unresolvable scheduled place likely means the user forgot
        # to author it.
        self._manifest_present = False

        # (agent_id, day) pairs whose daily plan was already validated against
        # PlaceDB (WP6 D5) — once per agent per day; cleared per run.
        self._validated_plans: set[tuple[str, str]] = set()

    # Lifecycle

    @staticmethod
    def _normalize_mode(mode: str) -> str:
        """Canonicalise a requested sim mode to ``survey`` or ``play`` (#102).

        ``live`` is the pre-#102 name for today's default behaviour and is the
        only accepted alias, mapped here and nowhere else. Anything else
        unrecognised warns and falls back to ``play`` rather than silently
        misbehaving.
        """
        normalized = (mode or "play").strip().lower()
        if normalized == "live":
            normalized = "survey"  # legacy alias (#102)
        if normalized not in ("survey", "play"):
            logger.warning(f"Unknown sim mode {mode!r} — defaulting to play")
            return "play"
        return normalized

    async def start_simulation(
        self,
        tick_seconds: int = 1,
        active_agents: list[str] | None = None,
        mode: str = "survey",
    ) -> dict:
        if (isinstance(tick_seconds, bool)
                or not isinstance(tick_seconds, (int, float))
                or tick_seconds <= 0):
            return {"status": "error", "error": "tick_seconds must be positive"}
        if self.running:
            return {"status": "already_running", "tick_seconds": self.tick_seconds}

        self.mode = self._normalize_mode(mode)

        # Truncate the log file so each run starts with a clean slate.
        for _h in logging.root.handlers:
            if isinstance(_h, logging.FileHandler):
                _h.stream.seek(0)
                _h.stream.truncate(0)
                break

        # Drop cached maps so each run reloads from disk (and picks up the right level).
        self._spatial.clear()
        self._last_cell.clear()
        self._frontier_failures.clear()
        self._scene_skips.clear()
        self._nearby_ids.clear()
        self._volume_probe_unavailable = False
        self._last_pos.clear()
        self._travel_from.clear()
        self._travel.clear()
        self._breadcrumbs.clear()
        self._last_order.clear()
        self._walk_plans.clear()
        self._tried_here.clear()
        self._stall_run.clear()
        self._walls.clear()
        self._last_raster.clear()
        self._last_ground.clear()
        self._footing_recoveries.clear()
        self._no_progress.clear()
        self._routes.clear()
        self._live_pos.clear()
        self._eyes.clear()
        self._bounces.clear()
        self._force_next_decide.clear()
        self._mission_complete.clear()

        self._load_agents(active_agents)
        if active_agents:
            for agent in self.agents.values():
                agent.set_active(True, self._agents_dir)
        bound_count = self._bind_agents()

        # Open (or create) the SQLite place cell store for this world.
        if self._agents_dir is not None:
            db_path = self._agents_dir.parent / "world_places.db"
            self.place_db = PlaceDB(db_path)

            # Authored ground truth, loaded before any tick so scheduled places
            # resolve without wake-seeding. Two sources feed the same manifest
            # pipeline (#23): Landmark_* actors in the level (ground truth,
            # wins on collision) and places.json (fallback / no-Unreal path).
            self._manifest_present = False
            try:
                level_actors = self.bridge.get_level_actors()
            except Exception as e:
                logger.warning(f"get_level_actors() failed ({e}) — landmarks skipped, "
                               f"places.json only")
                level_actors = []
            scanned = scan_landmarks(level_actors)
            landmarks = scanned["entries"]
            if scanned["suspects"]:
                logger.error(f"landmark suspects ignored: {scanned['suspects']}")
            manifest = places_manifest.load_manifest(self._agents_dir.parent / "places.json")
            if not landmarks:
                logger.info(f"landmarks: 0 (level) — no Landmark_* actors found, "
                           f"places.json: {len(manifest)}")
            merged = merge_entries(landmarks, manifest)
            if merged:
                summary = places_manifest.apply_manifest(self.place_db, self.world_grid, merged)
                logger.info(f"landmarks: {len(landmarks)} (level), places.json: {len(manifest)}, "
                           f"applied: {summary}")
                self._manifest_present = True

            # Allocate this run's SR<n> tag (per-world) and push it everywhere the
            # run needs stamping: observation filenames + the decision log.
            self.sim_run_id = sim_run.allocate_run(self._agents_dir.parent)
            sim_run.set_active_run(self.sim_run_id)
            self.bridge.sim_run_id = self.sim_run_id
            self.memory.sim_run_id = self.sim_run_id
            logger.info(f"Sim run {self.sim_run_id} — observations + decision log tagged")
            self._attach_run_log()

        # New run = a fresh wake for every agent (wake-time place seeding rearms).
        self._wake_stepped.clear()
        self._validated_plans.clear()
        self._movement_timing.clear()

        active = [a for a in self.agents.values() if a.is_active and a.has_unreal_binding]
        if not active:
            return {
                "status": "error",
                "error": "No agents could be bound to Unreal actors",
                "loaded_agents": list(self.agents.keys()),
                "bound_count": bound_count,
            }

        # Record each agent's run-start transform (once) so reset_agents can
        # teleport it back for reproducible re-runs.
        for agent in active:
            tf = self.bridge.get_character_transform(agent.bound_unreal_actor_name)
            if tf.get("location"):
                if agent.record_start_transform(tf["location"], tf.get("rotation"), self._agents_dir):
                    logger.info(f"[{agent.agent_id}] Start transform recorded: {tf['location']}")
            else:
                logger.warning(f"[{agent.agent_id}] Could not read start transform — reset won't reposition this agent")

        # Clear stale per-run state (goal, timers) so every run wakes clean.
        for agent in active:
            agent.reset_runtime_state(self._agents_dir)
            logger.info(f"[{agent.agent_id}] Runtime state reset for new run")

        # Teleport every agent back to their recorded start position.
        # Memories and place cells are intentionally preserved across runs.
        for agent in active:
            if agent.start_location and agent.has_unreal_binding:
                result = self.bridge.teleport(
                    agent.bound_unreal_actor_name, agent.start_location, agent.start_rotation
                )
                ok = result.get("success") is True or result.get("status") == "success"
                if ok:
                    logger.info(f"[{agent.agent_id}] Repositioned to start transform {agent.start_location}")
                else:
                    logger.warning(f"[{agent.agent_id}] Reposition failed: {result.get('error', 'unknown')}")
            else:
                logger.warning(f"[{agent.agent_id}] No start transform recorded — skipping reposition")

        # Survey-mission start placement (#96): after the reposition, move each
        # mission APC to the edge of covered ground next to its first target —
        # once, before the first tick. Mid-run the body always walks. Play mode
        # (#102) never pursues a mission target, so this placement is moot there.
        for agent in active:
            if agent.mission != "survey" or self.mode != "survey":
                continue
            placement = self._mission_start_placement(agent)
            if placement is None:
                continue
            result = self.bridge.teleport(
                agent.bound_unreal_actor_name, placement["location"], agent.start_rotation
            )
            ok = result.get("success") is True or result.get("status") == "success"
            if ok:
                logger.info(
                    f"[{agent.agent_id}] Mission start placement: swept cell "
                    f"{placement['cell']} beside first target {placement['target']}"
                )
            else:
                logger.warning(
                    f"[{agent.agent_id}] Mission start placement failed "
                    f"({result.get('error', 'unknown')}) — walking from start instead"
                )

        self.bridge.clear_scene_cache()

        # Check every authored destination before the first tick (#63). This does
        # not block the run — an APC with one bad task still has a day worth
        # watching — but it must never again be discovered halfway through a log.
        unresolved = self.preflight_places(active)
        # A name that resolves to two places is the same fault as one that
        # resolves to none, and just as invisible until a run is over (#75).
        merged = self.preflight_duplicate_places()

        self.running = True
        self.paused = False
        self.tick_seconds = tick_seconds
        self._tick_count = 0
        self._started_at = time.monotonic()
        self.world_clock.start()
        self._sim_task = asyncio.create_task(self._loop())

        logger.info(
            f"=== SIMULATION START === mode={self.mode} base_tick={tick_seconds}s "
            f"time={self.world_clock.now_text()} agents={[a.agent_id for a in active]}"
            + (f" UNRESOLVED PLACES: {len(unresolved)}" if unresolved else "")
            + (f" MERGED DUPLICATE PLACES: {len(merged)}" if merged else "")
        )
        return {
            "status": "started",
            "mode": self.mode,
            "tick_seconds": tick_seconds,
            "active_agents": [a.agent_id for a in active],
            "unresolved_places": unresolved,
            "merged_places": merged,
        }

    async def stop_simulation(self) -> dict:
        was_running = self.running
        self.running = False
        self.paused = False
        if self._sim_task:
            self._sim_task.cancel()
            self._sim_task = None
        elapsed = time.monotonic() - self._started_at if self._started_at else 0.0
        if was_running:
            # #101: how many times a body had to step itself off ground it
            # could not walk from — zero is the healthy number; SR56 needed a
            # count of this to exist at all.
            footing_total = sum(self._footing_recoveries.values())
            logger.info(
                f"=== SIMULATION STOP === ticks={self._tick_count} elapsed={elapsed:.1f}s "
                f"footing_recoveries={footing_total}")
        else:
            logger.info("=== SIMULATION STOP === (was not running)")
        self._started_at = None
        if self._run_log_handler is not None:
            logging.root.removeHandler(self._run_log_handler)
            self._run_log_handler.close()
            self._run_log_handler = None
        return {"status": "stopped", "ticks": self._tick_count, "elapsed_seconds": round(elapsed, 1)}

    async def pause_simulation(self) -> dict:
        self.paused = True
        return {"status": "paused"}

    async def resume_simulation(self) -> dict:
        if not self.running:
            return {"status": "error", "error": "Simulation not running"}
        self.paused = False
        return {"status": "resumed"}

    def get_status(self) -> dict:
        return {
            "running": self.running,
            "paused": self.paused,
            "mode": self.mode,
            "tick_seconds": self.tick_seconds,
            "tick_count": self._tick_count,
            "last_tick_duration_seconds": round(self._last_tick_duration, 2),
            "tick_in_progress": self._active_tick_entry is not None,
            "active_tick_entry": self._active_tick_entry,
            "agent_count": len(self.agents),
            "agents": [self._agent_summary(a) for a in self.agents.values()],
        }

    def recent_events(self, limit: int = 20) -> list[dict]:
        """Decision-feed entries from only the active simulation run."""
        return self.memory.get_recent_events(limit, sim_run_id=self.sim_run_id) if self.memory else []

    def clear_events(self) -> int:
        """Clear the decision feed (the cockpit's live log). Returns lines cleared."""
        return self.memory.clear_recent_events() if self.memory else 0

    # Agent loading and binding

    def _load_agents(self, active_only: list[str] | None) -> None:
        self.agents.clear()

        current_level = self.bridge.get_current_level()
        if not current_level:
            logger.warning("Could not determine current level — no agents loaded")
            return

        agents_dir = self.worlds_dir / current_level / "agents"
        if not agents_dir.exists():
            logger.warning(f"No agents directory for level '{current_level}': {agents_dir}")
            return

        self._agents_dir = agents_dir
        self.memory.update_agents_dir(agents_dir)

        self.world_grid = WorldGrid.load(self.worlds_dir / current_level / "world_grid.json")
        logger.info(f"World grid for '{current_level}': {self.world_grid.describe()}")

        self.world_clock = WorldClock.load(self.worlds_dir / current_level / "world.json")
        logger.info(f"World clock for '{current_level}': {self.world_clock.describe()}")
        logger.info(f"Loading agents for level '{current_level}' from {agents_dir}")

        for path in sorted(agents_dir.iterdir()):
            if not path.is_dir():
                continue
            agent_id = path.name
            if active_only and agent_id not in active_only:
                continue
            try:
                agent = Agent.load(agents_dir, agent_id)
            except Exception as e:
                logger.error(f"Failed to load agent '{agent_id}': {e}")
                continue

            self.agents[agent_id] = agent
            logger.info(f"Loaded agent '{agent_id}' -> Unreal actor '{agent.unreal_actor_name}'")

    def _bind_agents(self) -> int:
        """Resolve each agent to a live Unreal actor (find or spawn)."""
        for agent in self.agents.values():
            agent.clear_unreal_binding(self._agents_dir)

        bound_count = 0
        for agent in self.agents.values():
            actor = self.bridge.find_actor(agent.bound_unreal_actor_name)
            if not actor and agent.bound_unreal_actor_name != agent.unreal_actor_name:
                agent.clear_unreal_binding(self._agents_dir)
                actor = self.bridge.find_actor(agent.unreal_actor_name)

            if actor:
                agent.bind_unreal_actor(actor, self._agents_dir)
                logger.info(
                    f"[{agent.agent_id}] Bound to Unreal actor "
                    f"'{agent.bound_unreal_actor_name}' from hint '{agent.unreal_actor_name}'"
                )
                bound_count += 1
                continue

            if agent.blueprint_class:
                result = self.bridge.spawn_actor(
                    agent.blueprint_class,
                    agent.unreal_actor_name,
                )
                if result.get("success") is not False and result.get("name"):
                    agent.bind_unreal_actor(result, self._agents_dir)
                    logger.info(
                        f"[{agent.agent_id}] Spawned '{agent.blueprint_class}' as "
                        f"'{agent.bound_unreal_actor_name}'"
                    )
                    bound_count += 1
                else:
                    logger.warning(
                        f"[{agent.agent_id}] Spawn failed: {result.get('error') or result.get('message')}"
                    )
                    agent.clear_unreal_binding(self._agents_dir)
            else:
                logger.warning(
                    f"[{agent.agent_id}] Actor '{agent.unreal_actor_name}' not found "
                    f"and no blueprint_class set"
                )
                agent.clear_unreal_binding(self._agents_dir)
        return bound_count

    # Simulation loop

    def _attach_run_log(self) -> None:
        """Mirror the runner's log to ``logs/sim_runner.log`` for this run (#51).

        ``agent_decisions.log`` records completed decisions only, so a run whose
        APCs never decide leaves no trace on disk at all. Everything that would
        explain such a run — cognition skips, LLM exceptions, bind failures —
        goes to stdout, which dies with the console window. Attached here rather
        than in ``sim_runner`` because the log directory is only known once a
        level's agents are loaded. Truncating per run matches the decision log.
        """
        if self.memory.decisions_log is None:
            return
        path = (self.memory.decisions_log.parent / "sim_runner.log").resolve()
        for handler in logging.root.handlers:
            if (isinstance(handler, logging.FileHandler)
                    and Path(handler.baseFilename).resolve() == path):
                self._run_log_handler = handler
                return
        try:
            handler = logging.FileHandler(path, mode="w", encoding="utf-8")
        except OSError as e:
            logger.error(f"Run log unavailable at {path}: {e} — console only")
            return
        handler.setFormatter(
            logging.Formatter("%(asctime)s %(levelname)s [%(sim_run)s] %(message)s")
        )
        handler.addFilter(sim_run.SimRunFilter())
        logging.root.addHandler(handler)
        self._run_log_handler = handler
        # The host process may never have called basicConfig (web UI, MCP), in
        # which case root sits at WARNING and drops every INFO record before any
        # handler sees it. The run log is worthless without them.
        logging.getLogger("AgentRuntime").setLevel(logging.INFO)
        logger.info(f"Run log: {path}")

    def _not_ready_reason(self, agent: Agent) -> str:
        """Why an active agent was dropped from this tick (mirrors the ready filter)."""
        if agent.is_busy:
            return "busy"
        if not agent.cooldown_expired():
            return f"cooling down ({agent.tick_interval_seconds}s)"
        if self._has_open_chat(agent):
            return "chat open"
        return "unbound or filtered"

    @staticmethod
    def _tick_outcomes(result: dict) -> str:
        """One-line per-agent outcome roll-up for a tick (#51).

        Makes "observed but never decided" legible at a glance: a run of
        ``dufus=idle(scene_unchanged)`` lines says the cognition gate is holding
        the agent shut, which no decision-log entry would ever reveal.
        """
        parts = []
        for entry in result.get("agent_results") or []:
            if not isinstance(entry, dict):
                continue
            label = entry.get("action") or entry.get("status") or "?"
            reason = entry.get("reason")
            parts.append(
                f"{entry.get('agent_id', '?')}={label}" + (f"({reason})" if reason else "")
            )
        return ", ".join(parts)

    async def _loop(self) -> None:
        # Spool-up: each agent wakes and orients itself before the first tick.
        # Both modes (#102) need this; only the removed "explore" mode skipped it.
        await self._wake_agents()
        self._print_sim_status()
        self._flush_model_pie()
        logger.info(
            f"Simulation loop running — base tick {self.tick_seconds}s; the sleep starts "
            f"only after each tick's processing, so the interval expands with observation/LLM time"
        )
        while self.running:
            if not self.paused:
                started = time.monotonic()
                result = None
                try:
                    result = await self.tick(entry="automatic_tick")
                except Exception as e:
                    logger.error(f"Tick error: {e}")
                duration = time.monotonic() - started
                self._last_tick_duration = duration
                if not result or result.get("status") != "busy":
                    self._tick_count += 1
                if result and result.get("ticked"):
                    outcomes = self._tick_outcomes(result)
                    logger.info(
                        f"Tick #{self._tick_count}: {result['ticked']} agent(s) in {duration:.2f}s "
                        f"— next in {self.tick_seconds}s (effective interval ~{duration + self.tick_seconds:.2f}s)"
                        + (f" — {outcomes}" if outcomes else "")
                    )
                elif result is not None and result.get("status") != "busy":
                    # A tick that moved no agent at all is the exact shape of the
                    # SR30 blackout (#51); it must not pass unremarked.
                    logger.info(f"Tick #{self._tick_count}: no agent ran in {duration:.2f}s")
                self._print_sim_status()
                self._flush_model_pie()
            # Base pacing sleeps AFTER the tick completes: with N avatars the gap
            # between ticks is their full observation + thinking time plus the base,
            # so ticks can never pile up and over-drive the avatars.
            await asyncio.sleep(self.tick_seconds)
        logger.info("Simulation loop exited")

    def _print_sim_status(self) -> None:
        """Push agent names and current goals to the PIE viewport as on-screen debug messages."""
        active = sorted(
            (a for a in self.agents.values() if a.is_active and a.has_unreal_binding),
            key=lambda a: a.agent_id,
        )
        elapsed = int(time.monotonic() - self._started_at) if self._started_at else 0
        header = f"[SIM] tick={self._tick_count}  elapsed={elapsed}s  mode={self.mode}"
        self.bridge.print_to_screen(header, key=99, duration=30.0)
        for i, agent in enumerate(active):
            goal = agent.current_goal
            if len(goal) > 45:
                goal = goal[:42] + "..."
            self.bridge.print_to_screen(f"  {agent.agent_id}: {goal}", key=100 + i, duration=30.0)

    def _agent_slot(self, agent_id: str) -> int:
        """Stable PIE-line index for an agent (matches _print_sim_status ordering)."""
        ids = sorted(
            a.agent_id for a in self.agents.values()
            if a.is_active and a.has_unreal_binding
        )
        try:
            return ids.index(agent_id)
        except ValueError:
            return 0

    def _pie_activity(self, agent_id: str, message: str) -> None:
        """Update this agent's PIE activity line (key 130+slot), in place each tick.

        Bridge is single-socket, so call only from the sequential tick phases
        (observe / act) — never from the parallel perceive+decide phase.

        No bridge means there is no viewport to draw on, which is an ordinary
        offline state; a status line must never be what takes a decision down.
        Every other failure still raises.
        """
        if self.bridge is None:
            return
        self.bridge.print_to_screen(
            f"  {agent_id}: {message}",
            key=130 + self._agent_slot(agent_id),
            duration=30.0,
        )

    def _set_activity(self, agent: Agent, state: str) -> None:
        """Push a cognitive/physical activity label to the agent's actor.

        Sets AIState (fires OnAIStateChanged) so the above-head status bubble can
        show what the agent is doing — e.g. "observing", "thinking". Single-socket
        bridge, so call only from the sequential tick phases (observe / act),
        never from the parallel perceive+decide phase.
        """
        if agent.has_unreal_binding:
            self.bridge.set_ai_state(agent.bound_unreal_actor_name, state)

    def _flush_model_pie(self) -> None:
        """Drain queued Ollama model-load lines to PIE (sequential phase only)."""
        from .ollama_adapter import take_pending_pie
        for msg in take_pending_pie():
            self.bridge.print_to_screen(msg, key=200, duration=20.0)

    async def _wake_agents(self) -> None:
        """Spool-up: each agent wakes and orients itself before the first tick.

        Phase 1 (sequential, bridge): for each agent, check PlaceDB for a
          known place.  If known → skip sweep; if unknown → run 180° sweep,
          ingest compass observations into PlaceDB.
        Phase 2 (parallel, thread pool): fire orient LLM calls simultaneously.
        Phase 3 (sequential, bridge): apply goals + execute each first action.
        """
        if not self.llm:
            logger.info("Wake-up skipped — no LLM router")
            return
        world_time = self.world_clock.now_text()
        active = [a for a in self.agents.values() if a.is_active and a.has_unreal_binding]

        # Phase 1: bridge (sequential) — sweep unknown places, skip known ones.
        needs_orient: list[tuple] = []   # (agent, context, memories)
        for agent in active:
            try:
                tf = self.bridge.get_character_transform(agent.bound_unreal_actor_name)
                loc = tf.get("location")
                rot = tf.get("rotation")
                self._begin_movement_timing(agent.agent_id, loc)
                grid, place = self._grid_and_place(agent.agent_id, loc)
                col, row = self._cell_col_row(grid)

                known_place = None
                familiarity: dict = {}
                if self.place_db and col is not None:
                    known_place = self.place_db.get_place(col, row)
                    familiarity = self.place_db.agent_familiarity(agent.agent_id, col, row)

                # Sequencer directive at the TRUE spawn position, before any
                # first action can move the agent: seeds a first-time scheduled
                # place right here and tells the orient prompt, with ground
                # truth, whether the agent is already where it should be —
                # instead of letting the LLM guess and walk off (Maren, SR2).
                directive = self._wake_directive(agent, loc, grid, world_time)
                visual_place_name = (
                    (directive or {}).get("place")
                    if (directive or {}).get("status") == "act" else None
                )
                place_image = None
                if self.place_db and col is not None:
                    place_image = self.place_db.current_place_image(
                        agent.agent_id, col, row, visual_place_name
                    )

                if place_image:
                    # A complete shared visual memory is the survey gate. A
                    # name/sweep breadcrumb alone is not enough.
                    self._link_place_visual_history(agent.agent_id, place_image)
                    # Pass personal familiarity so the orient prompt can tell the
                    # agent whether this is THEIR place or just a place they've
                    # visited, giving them the signal to stay vs. move on.
                    logger.info(
                        f"[{agent.agent_id}] WAKE {world_time} at mapped place "
                        f"'{place_image.get('name') or (known_place or {}).get('name') or visual_place_name or grid.get('key')}' "
                        f"(visits={familiarity.get('visit_count',0)}, "
                        f"named_by_me={familiarity.get('named_by_me',False)}) — skipping sweep"
                    )
                    memories = self.memory.get_relevant_memories(agent.agent_id)
                    context = {
                        "world_time": world_time, "location": loc, "rotation": rot,
                        "grid": grid, "place": place, "views": [],
                        "directions": self._direction_places(agent.agent_id, loc, rot),
                        "known_place": (place_image.get("name")
                                        or (known_place or {}).get("name")
                                        or visual_place_name),
                        "place_image_id": place_image["place_image_id"],
                        "place_description": place_image.get("description", ""),
                        "familiarity": familiarity,
                        "schedule": directive,
                    }
                    needs_orient.append((agent, context, memories))
                    continue

                known_chars = [
                    a.display_name
                    for a in self.agents.values()
                    if a.agent_id != agent.agent_id and a.has_unreal_binding
                ]
                if self.mode == "survey":
                    views = self._wake_sweep(agent, loc, rot, known_chars)
                    place_image = self._ingest_wake_views(
                        agent.agent_id, col, row, views, world_time, visual_place_name
                    )
                else:
                    # Play (#102): live on the grid already built — no new
                    # place visuals, so the wake look-around is skipped.
                    views, place_image = [], None

                memories = self.memory.get_relevant_memories(agent.agent_id)
                context = {
                    "world_time": world_time, "location": loc, "rotation": rot,
                    "grid": grid, "place": place, "views": views,
                    "directions": self._direction_places(agent.agent_id, loc, rot),
                    "known_place": None,
                    "place_image_id": (place_image or {}).get("place_image_id"),
                    "place_description": (place_image or {}).get("description", ""),
                    "familiarity": familiarity,
                    "schedule": directive,
                }
                needs_orient.append((agent, context, memories))
            except Exception as e:
                logger.error(f"[{agent.agent_id}] Wake sweep failed: {e} — keeping authored goal")

        if not needs_orient:
            return

        # Phase 2: orient LLM calls (parallel via thread pool).
        orient_tasks = [
            asyncio.to_thread(self.llm.orient, agent, ctx, mems)
            for agent, ctx, mems in needs_orient
        ]
        orientations = await asyncio.gather(*orient_tasks, return_exceptions=True)

        # Phase 3: apply orientations + first actions (sequential, bridge).
        for (agent, context, memories), orientation in zip(needs_orient, orientations):
            try:
                loc = context["location"]
                rot = context["rotation"]
                grid = context["grid"]
                place = context["place"]
                views = context.get("views", [])

                if isinstance(orientation, Exception):
                    logger.error(f"[{agent.agent_id}] Orient call failed: {orientation}")
                    orientation = None
                if not orientation:
                    logger.warning(
                        f"[{agent.agent_id}] Wake-up produced no orientation — "
                        f"keeping authored goal: {agent.current_goal!r}"
                    )
                    continue

                goal = str(orientation.get("current_goal") or "").strip()
                agenda_goal = str(
                    (((context.get("schedule") or {}).get("agenda") or {})
                     .get("right_now") or {}).get("objective") or ""
                ).strip()
                if agenda_goal:
                    goal = agenda_goal
                if goal:
                    self._sync_agenda_goal(agent, goal)

                self._record_place(agent.agent_id, loc, orientation.get("place"))

                first_action = validate(agent, orientation, {})
                first_result = None
                if first_action:
                    forward = next((v for v in views if v["direction"] == "E"), None)
                    wake_obs = {
                        "location": loc, "rotation": rot,
                        "image_path": forward["image_path"] if forward else None,
                        # Named-place travel must route from the true wake cell;
                        # omitting this made _execute_routed_walk fall back to a
                        # brief direct beeline at the final place anchor.
                        "grid": grid, "place": place,
                        "world_time": context.get("world_time"),
                        "schedule": context.get("schedule"),
                    }
                    # Wake is a tick like any other: the APC may open the run by
                    # asking to survey where it woke up, and that must reach the
                    # same handler the normal path uses (SR39). Same for a cell
                    # ruling — SR42's wake opened with refuse_cell and the bridge
                    # answered "Unknown action".
                    verdict = self._apply_cell_verdict(agent, first_action, wake_obs)
                    if verdict is not None:
                        first_action = verdict
                    first_action, pending = self._resolve_survey_here(
                        agent, first_action, wake_obs)
                    if pending:
                        first_result = {"status": "survey_pending",
                                        "interrupt_id": pending["interrupt_id"]}
                    else:
                        first_result = self._execute_world_action(agent, first_action, wake_obs)
                        self._mark_first_walk_accepted(
                            agent.agent_id, first_action, first_result)

                self.memory.record(
                    agent_id=agent.agent_id,
                    observation={
                        "wake": True, "world_time": context["world_time"], "location": loc,
                        "grid": grid, "place": place,
                        "place_image_id": context.get("place_image_id"),
                        "views": [v["direction"] for v in views],
                        "_thought": orientation.get("thought_summary"),
                    },
                    action={"type": "wake", "first_action": first_action},
                    result=first_result or {"status": "ok"},
                    memory_update=orientation.get("memory_update"),
                    importance=float(orientation.get("importance", 0.7)),
                    timing=self._movement_timing_snapshot(agent.agent_id),
                )
                logger.info(
                    f"[{agent.agent_id}] WAKE {context['world_time']} place={place or 'unknown'} "
                    f"views={len(views)} goal={goal or agent.current_goal!r} "
                    f"first_action={first_action.get('type') if first_action else None}"
                )
            except Exception as e:
                logger.error(f"[{agent.agent_id}] Wake orientation failed: {e} — keeping authored goal")

    def _ingest_wake_views(self, agent_id: str, col, row,
                           views: list[dict], world_time: str,
                           place_name: str = None) -> dict | None:
        """Record a wake sweep's views in the shared PlaceDB.

        Each view's landmarks feed the cell's compass-observation table, and a
        non-empty sweep drops the community breadcrumb (``mark_swept``): the
        wake look-around observed five headings from inside the cell, which
        counts as the district's community sweep (user, 2026-07-06). Scheduled
        "act" ticks are sweep-exempt, so without this an agent working its own
        cell (Dufus at home) would leave its district unexplored on the map
        forever. No-op without a PlaceDB or grid indices; an empty sweep
        (no transform / every heading failed) records nothing.
        """
        if not self.place_db or col is None:
            return None
        for v in views:
            if v.get("landmarks"):
                self.place_db.ingest_compass(
                    agent_id, col, row, yaw_to_compass(v["yaw"]), v["landmarks"]
                )
        image = self._save_place_visual(agent_id, col, row, views, place_name)
        if views and self.place_db.mark_swept(agent_id, col, row, world_time):
            logger.info(
                f"[{agent_id}] wake: community place cell swept at ({col},{row}) "
                f"— breadcrumb dropped"
            )
        return image

    def _wake_sweep(self, agent: Agent, loc, rot, known_characters: list[str]) -> list[dict]:
        """Capture the four absolute cardinal views of a new place.

        Turn in 90-degree steps, capture a view at each, perceive it (VLM turns
        pixels into named sightings), then restore the original facing so
        movement directions stay relative to it.

        Each view carries what was seen plus what the agent's own map already
        knows about the cell one step away in that direction. All sightings
        are accumulated into the agent's spatial map. A failed turn, capture,
        or perception just degrades that view — never aborts the wake. Calls
        are strictly sequential (single-socket bridge).
        """
        base_yaw = _yaw_of(rot)
        xyz = _loc_xyz(loc)
        if xyz is None or base_yaw is None:
            logger.warning(f"[{agent.agent_id}] No transform — waking without a look-around")
            return []
        views: list[dict] = []
        sightings: list[dict] = []
        smap = self._spatial_map(agent.agent_id)
        for direction, yaw in _SWEEP_VIEWS:
            turn = self.bridge.set_facing(agent.bound_unreal_actor_name, loc, yaw)
            if turn.get("error"):
                logger.warning(f"[{agent.agent_id}] sweep turn '{direction}' failed: {turn['error']}")
                continue
            time.sleep(0.25)  # let the rotated frame render before capturing
            image_path = self.bridge.capture_view(
                agent.bound_unreal_actor_name, agent.agent_id, self._agents_dir, f"wake_{direction}"
            )
            if not image_path:
                logger.warning(f"[{agent.agent_id}] sweep capture '{direction}' failed")
                continue
            seen = self.perceiver.perceive(image_path, known_characters)
            if seen.get("error"):
                logger.warning(f"[{agent.agent_id}] sweep perception '{direction}' failed: {seen['error']}")
            self._note_eyes(agent.agent_id, loc, yaw, seen)
            self._record_perception_pair(
                agent.agent_id, image_path, seen, location=loc, yaw=yaw,
                grid=self.world_grid.locate(xyz[0], xyz[1]),
                world_time=self.world_clock.now_text(), context="wake")
            sightings.extend(seen.get("landmarks") or [])
            tx, ty, _ = _offset_location(*xyz, yaw, _STEP_DISTANCE)
            views.append({
                "direction": direction, "yaw": yaw, "image_path": image_path,
                "caption": seen.get("caption", ""),
                "at": [xyz[0], xyz[1]],
                "landmarks": seen.get("landmarks", []),
                "characters": seen.get("characters", []),
                "places": smap.place_labels(self.world_grid.locate(tx, ty)["key"]),
            })
        # Face back the way the avatar woke up.
        self.bridge.teleport(agent.bound_unreal_actor_name, loc, rot)
        # Everything seen during the sweep goes into the mental map.
        if sightings:
            smap.ingest(xyz[0], xyz[1], sightings)
            smap.save(self._agents_dir / agent.agent_id / "spatial_map.json")
        return views

    def _world_relative_path(self, path: str | Path) -> str:
        """Return a world-relative generated-artifact path when possible."""
        candidate = Path(path).resolve()
        world_root = self._agents_dir.parent.resolve()
        try:
            return str(candidate.relative_to(world_root))
        except ValueError:
            return str(candidate)

    def _save_place_visual(self, agent_id: str, col: int, row: int,
                           views: list[dict], place_name: str = None) -> dict | None:
        """Compose and register a complete four-view visual memory."""
        if self.place_db is None or col is None:
            return None
        by_direction = {
            str(view.get("direction", "")).upper(): view
            for view in views if view.get("image_path")
        }
        if any(direction not in by_direction for direction in place_visuals.CARDINAL_DIRECTIONS):
            logger.warning(
                f"[{agent_id}] place visual ({col},{row}) incomplete — "
                f"have {sorted(by_direction)}; needs N/S/E/W"
            )
            return None

        # Where the frames were shot. A composite whose capture point is not in
        # the cell it is filed under is corpus poison — SR33 filed two cells
        # from one spot — so refuse to write it rather than log a warning.
        captured_xy = next((tuple(v["at"]) for v in views
                            if isinstance(v.get("at"), (list, tuple)) and len(v["at"]) >= 2), None)
        if captured_xy is not None:
            shot_in = self.world_grid.locate(captured_xy[0], captured_xy[1])
            if (shot_in.get("col"), shot_in.get("row")) != (col, row):
                logger.error(
                    f"[{agent_id}] place visual ({col},{row}) REFUSED — frames were shot "
                    f"at ({captured_xy[0]:.0f},{captured_xy[1]:.0f}) in cell "
                    f"({shot_in.get('col')},{shot_in.get('row')})"
                )
                return None

        shared_dir = self._agents_dir.parent / "places" / "images"
        composite_path = shared_dir / f"{uuid.uuid4().hex}.png"
        sources = {d: by_direction[d]["image_path"] for d in place_visuals.CARDINAL_DIRECTIONS}
        try:
            place_visuals.build_place_composite(sources, composite_path, col, row)
            description = "\n".join(
                f"{d}: {str(by_direction[d].get('caption') or '').strip()}"
                for d in place_visuals.CARDINAL_DIRECTIONS
                if str(by_direction[d].get("caption") or "").strip()
            )
            image = self.place_db.record_place_image(
                agent_id, col, row,
                self._world_relative_path(composite_path),
                {d: self._world_relative_path(sources[d])
                 for d in place_visuals.CARDINAL_DIRECTIONS},
                description=description,
                place_name=place_name,
                captured_xy=captured_xy,
            )
            self._expose_place_visual_history(agent_id, image)
            logger.info(
                f"[{agent_id}] place visual saved: {image['place_image_id']} "
                f"({image['place_kind']} {col},{row} revision {image['revision']})"
            )
            return image
        except Exception as e:
            if composite_path.exists():
                composite_path.unlink()
            logger.error(f"[{agent_id}] place visual save failed: {e}")
            return None

    def _link_place_visual_history(self, agent_id: str, image: dict) -> None:
        """Link one shared place image into the APC's inspectable history."""
        linked = self.place_db.link_agent_to_place_image(agent_id, image["place_image_id"])
        if not linked:
            return
        self._expose_place_visual_history(agent_id, linked)

    def _expose_place_visual_history(self, agent_id: str, image: dict) -> None:
        """Expose an already-recorded visual-history link as an image file."""
        place_visuals.expose_in_agent_history(
            self.place_db.absolute_image_path(image),
            self._agents_dir / agent_id / "observations",
            image["place_image_id"],
        )

    async def _run_tick_entry(self, entry: str, operation) -> dict:
        """Run one tick-like operation, or reject it without waiting.

        The event loop cannot switch tasks between the active-entry check and
        assignment, which makes the busy decision atomic for this manager.
        ``asyncio.Lock`` remains the actual critical-section guard.
        """
        if self._active_tick_entry is not None:
            return {
                "status": "busy",
                "error": "A simulation tick is already in progress",
                "requested_entry": entry,
                "active_entry": self._active_tick_entry,
            }

        self._active_tick_entry = entry
        await self._tick_lock.acquire()
        try:
            return await operation()
        finally:
            self._tick_lock.release()
            self._active_tick_entry = None

    async def tick(self, entry: str = "tick") -> dict:
        """Run a whole-simulation tick unless another tick entry is active."""
        return await self._run_tick_entry(entry, self._tick_impl)

    async def _tick_impl(self) -> dict:
        """Run one simulation tick across all ready agents.

        Three phases keep Unreal bridge calls sequential while LLM calls
        run in parallel across agents:
          1. Observe (sequential, bridge): cheap state gate, then screenshot only
             for agents whose cognition was rearmed
          2. Perceive + decide (parallel, thread pool): Gemini → Haiku
          3. Act (sequential, bridge): execute action + persist memory
        """
        ready = [
            a for a in self.agents.values()
            if (a.is_active and not a.is_busy and a.cooldown_expired()
                and not self._has_open_chat(a))
        ]
        # Agents mid-sweep (#11.1) run a deterministic, bridge-only, no-LLM step —
        # keep them out of the perceive/decide phases until the sweep finishes.
        sweeping = [a for a in ready if self._has_active_survey(a)]
        ready = [a for a in ready if not self._has_active_survey(a)]
        # Agents part-way through a grown step (#86) walk the next hop the same
        # way: bridge only, no perceive, no decide. A survey outranks a walk —
        # an APC that has arrived somewhere worth surveying is done travelling.
        walking = [a for a in ready if self._has_active_walk(a)]
        ready = [a for a in ready if not self._has_active_walk(a)]
        # Survey-mission APCs (#96) with no survey, no walk, and no checkpoint
        # owed get their next target chosen by code — no perceive, no decide.
        # The one tick this deliberately leaves to the LLM is the checkpoint:
        # a finished sweep files a _force_next_decide debt, and while that debt
        # stands the mission bucket declines the agent, so it falls through to
        # the ordinary observe/perceive/decide path exactly once per cell.
        missioning = [a for a in ready if self._mission_wants_tick(a)]
        ready = [a for a in ready if not self._mission_wants_tick(a)]

        # Account for every active agent this tick (#51). An APC dropped by the
        # ready filter — wedged is_busy, cooling down, holding an open chat —
        # otherwise disappears from the simulation with nothing in any log to
        # mark it: no decision entry, no skip line, no capture. Silence must not
        # be the same observation as "nothing was wrong".
        running = ({id(a) for a in ready} | {id(a) for a in sweeping}
                   | {id(a) for a in walking} | {id(a) for a in missioning})
        excluded = [
            f"{a.agent_id} ({self._not_ready_reason(a)})"
            for a in sorted(self.agents.values(), key=lambda a: a.agent_id)
            if a.is_active and id(a) not in running
        ]
        if excluded:
            logger.info(f"Tick skipped {len(excluded)}: {', '.join(excluded)}")

        results = []
        # Sweep phase (sequential — single bridge socket, like the others).
        for agent in sweeping:
            self._set_activity(agent, "sweeping")
            results.append(self._pulse_sweep(agent))

        # Walk phase (sequential — same single bridge socket).
        for agent in walking:
            self._set_activity(agent, "walking")
            results.append(self._pulse_walk(agent))

        # Mission phase (#96, sequential — same single bridge socket).
        for agent in missioning:
            self._set_activity(agent, "on mission")
            results.append(self._pulse_mission(agent))

        # Phase 1: observe (sequential, bridge)
        observations: dict[str, dict | None] = {}
        timings: dict[str, dict] = {}
        for agent in ready:
            self._set_activity(agent, "sampling")
            started = time.monotonic()
            observations[agent.agent_id] = self._observe_agent(agent)
            timings[agent.agent_id] = {
                "observe_ms": round((time.monotonic() - started) * 1000.0, 3)
            }
        self._attach_nearby_characters(observations)

        # Phase 2: perceive + decide (parallel, thread pool)
        llm_needed = [a for a in ready if observations.get(a.agent_id) is not None]
        # Flag "thinking" sequentially before launching the parallel decide batch —
        # the LLM call blocks for the bulk of the tick, so this is what's on screen.
        for agent in llm_needed:
            self._set_activity(agent, "thinking")
        decisions: dict[str, dict | None] = {}
        if llm_needed:
            tasks = [
                asyncio.to_thread(self._timed_perceive_and_decide,
                                  agent, observations[agent.agent_id])
                for agent in llm_needed
            ]
            results_raw = await asyncio.gather(*tasks, return_exceptions=True)
            for agent, result in zip(llm_needed, results_raw):
                if isinstance(result, Exception):
                    decisions[agent.agent_id] = result
                else:
                    decisions[agent.agent_id], timings[agent.agent_id]["llm_ms"] = result

        # Phase 3: act (sequential, bridge) — appends to the sweep results.
        for agent in ready:
            obs = observations.get(agent.agent_id)
            decision = decisions.get(agent.agent_id)
            if obs is not None:
                obs["_timing"] = timings[agent.agent_id]
            results.append(self._act_agent(agent, decision, obs))

        return {"ticked": len(results), "agent_results": results}

    async def pulse_agent(self, agent_id: str) -> dict:
        """Run one agent immediately unless another tick entry is active."""
        return await self._run_tick_entry(
            f"agent_tick:{agent_id}", lambda: self._pulse_agent_impl(agent_id)
        )

    async def _pulse_agent_impl(self, agent_id: str) -> dict:
        """Single-agent tick implementation; caller owns the shared tick lock."""
        agent = self.agents.get(agent_id)
        if not agent:
            return {"error": f"Agent '{agent_id}' not loaded"}
        if self._has_open_chat(agent):
            return {"status": "chat_open", "agent_id": agent_id,
                    "error": "End or convert the open chat before pulsing this APC"}
        if self._has_active_survey(agent):
            return self._pulse_sweep(agent)
        self._end_walk_plan(agent_id, "operator pulsed this APC")
        self._set_activity(agent, "sampling")
        # This endpoint is an explicit operator pulse. It intentionally bypasses
        # settled-agent suppression so "pulse" still means "think now".
        started = time.monotonic()
        obs = self._observe_agent(agent, force_cognition=True)
        timing = {"observe_ms": round((time.monotonic() - started) * 1000.0, 3)}
        if obs is None:
            grid, place = self._last_grid_place.get(agent_id, (None, []))
            return {"agent_id": agent_id, "action": "idle", "reason": "scene_unchanged",
                    "grid": grid, "place": place}
        self._attach_nearby_characters({agent_id: obs})
        self._set_activity(agent, "thinking")
        decision, timing["llm_ms"] = await asyncio.to_thread(
            self._timed_perceive_and_decide, agent, obs)
        obs["_timing"] = timing
        return self._act_agent(agent, decision, obs)

    def _timed_perceive_and_decide(self, agent: Agent, observation: dict) -> tuple:
        """Run the model phase and return its own wall-clock latency."""
        started = time.monotonic()
        try:
            result = self._perceive_and_decide(agent, observation)
        except Exception as exc:
            result = exc
        return result, round((time.monotonic() - started) * 1000.0, 3)

    def _begin_movement_timing(self, agent_id: str, location) -> None:
        """Start the per-run wake → movement milestone clock for one APC."""
        xyz = _loc_xyz(location)
        self._movement_timing[agent_id] = {
            "wake_at": time.monotonic(),
            "start_xy": (xyz[0], xyz[1]) if xyz is not None else None,
            "walk_accepted_at": None,
            "displaced_at": None,
        }

    def _mark_first_walk_accepted(self, agent_id: str, action: dict,
                                  result: dict) -> None:
        timing = self._movement_timing.get(agent_id)
        if not timing or timing["walk_accepted_at"] is not None:
            return
        if action.get("type") not in {"walk_to", "wander"} or result.get("error"):
            return
        if result.get("status") in {"accepted", "success", "ok"} or result.get("success") is True:
            timing["walk_accepted_at"] = time.monotonic()

    def _mark_first_displacement(self, agent_id: str, location) -> None:
        timing = self._movement_timing.get(agent_id)
        xyz = _loc_xyz(location)
        if (not timing or timing["walk_accepted_at"] is None
                or timing["displaced_at"] is not None or timing["start_xy"] is None
                or xyz is None):
            return
        if math.hypot(xyz[0] - timing["start_xy"][0],
                      xyz[1] - timing["start_xy"][1]) >= _MOVEMENT_START_CM:
            timing["displaced_at"] = time.monotonic()

    def _movement_timing_snapshot(self, agent_id: str) -> dict:
        timing = self._movement_timing.get(agent_id)
        if not timing:
            return {}
        out = {}
        if timing["walk_accepted_at"] is not None:
            out["wake_to_walk_accepted_ms"] = round(
                (timing["walk_accepted_at"] - timing["wake_at"]) * 1000.0, 3)
        if timing["displaced_at"] is not None:
            out["wake_to_first_displacement_ms"] = round(
                (timing["displaced_at"] - timing["wake_at"]) * 1000.0, 3)
        return out

    # ── Tick phases ──────────────────────────────────────────────────────────

    def _observe_agent(self, agent: Agent, force_cognition: bool = False) -> dict | None:
        """Phase 1: gather world state via bridge.

        Returns an observation dict, or None if the scene is unchanged
        (scene_unchanged agents are skipped by phases 2 and 3).
        """
        agent_id = agent.agent_id
        # One-shot debt from a resolved survey (or any state change that must
        # be thought about now): consume it as a forced cognition tick.
        if agent_id in self._force_next_decide:
            self._force_next_decide.discard(agent_id)
            force_cognition = True
        # The lizard-brain gate must run before camera capture. In particular,
        # a stationary APC at its scheduled mapped place should not create a
        # duplicate PNG merely to discover that cognition is asleep.
        state_reader = getattr(self.bridge, "get_character_state", None)
        if callable(state_reader):
            observation = state_reader(agent.bound_unreal_actor_name)
        else:
            # Compatibility for engine-neutral adapters that have not yet split
            # cheap state sampling from their observation implementation.
            observation = self.bridge.get_observation(
                agent.bound_unreal_actor_name, agent_id, self._agents_dir
            )
        observation["known_characters"] = [
            a.display_name
            for a in self.agents.values()
            if a.agent_id != agent_id and a.has_unreal_binding
        ]
        grid, place = self._grid_and_place(agent_id, observation.get("location"))
        observation["grid"] = grid
        observation["place"] = place
        # Stash so a scene-unchanged skip can still report position (pure lookups,
        # no engine/LLM) — explore mode reports grid+place every tick and the
        # standard path must too, even when the diff gate skips perception.
        self._last_grid_place[agent_id] = (grid, place)
        observation["world_time"] = self.world_clock.now_text()
        active_interrupt = getattr(agent, "active_interrupt", None)
        if isinstance(active_interrupt, dict):
            observation["active_interrupt"] = active_interrupt
        observation["directions"] = self._direction_places(
            agent_id, observation.get("location"), observation.get("rotation")
        )
        observation["last_move"] = self._last_move_fact(agent_id, observation.get("location"))
        observation["wedge"] = self._wedge_fact(
            agent_id, observation.get("last_move"), observation.get("directions"))
        observation["frontier"] = self._frontier_fact(grid)
        # A mission APC only reaches this path on its per-cell checkpoint (#96)
        # — tell it so, or it spends the one paid decision planning travel the
        # mission will run itself.
        if agent.mission == "survey":
            observation["mission"] = (
                self._mission_fact(agent_id) if self.mode == "survey"
                # Play (#102): the mission is on hold, not gone.
                else {"kind": "paused"}
            )
        observation["travel"] = self._travel_fact(agent_id, observation.get("location"), grid)
        # Standing inside a no-go patch is its own fact (SR44: Dufus stood in
        # the pergola yard and re-refused it eight ticks running, because the
        # patch only ever rendered on step targets, never underfoot).
        xyz_here = _loc_xyz(observation.get("location"))
        if self.place_db and xyz_here:
            here_patches = self.place_db.patches_at(xyz_here[0], xyz_here[1])
            if here_patches:
                observation["here_no_go"] = here_patches[0]
        # Cells walked into and straight back out of, twice or more (#26).
        bounced = [{"cell": cell, "count": count}
                   for cell, count in (self._bounces.get(agent_id) or {}).items()
                   if count >= 2]
        if bounced:
            observation["bounce"] = sorted(
                bounced, key=lambda b: (-b["count"], b["cell"]))

        # Structured place context from SQLite (None if not yet named).
        if self.place_db and grid:
            col, row = self._cell_col_row(grid)
            if col is not None:
                self.place_db.touch(agent_id, col, row)
                observation["place_context"] = self.place_db.get_place(col, row)
                if observation["place_context"]:
                    observation["place_image_id"] = observation["place_context"].get(
                        "place_image_id"
                    )

        # Live map telemetry (#18): remember where this agent was last observed.
        self._record_live_pos(agent_id, observation)
        self._mark_first_displacement(agent_id, observation.get("location"))

        # Proximity is a cheap deterministic event source. It must run before
        # the visual-diff gate because _attach_nearby_characters normally runs
        # after this method, when a suppressed observation is already gone.
        nearby_now = self._nearby_agent_ids(agent_id, _loc_xyz(observation.get("location")))
        nearby_before = self._nearby_ids.get(agent_id)
        nearby_changed = nearby_before is not None and nearby_now != nearby_before
        self._nearby_ids[agent_id] = nearby_now

        # Stuck detection: "moving" but not actually advancing (wedged on an
        # obstacle the navmesh doesn't route around). Attach to the observation so
        # the decision prompt can tell the agent to pick another direction.
        moving = "moving" in str(observation.get("current_action") or "").lower()
        stuck = self._detect_stuck(agent_id, _loc_xyz(observation.get("location")), moving)
        observation["stuck"] = stuck
        # Radar (#92): all eight headings, every tick, before anything has gone
        # wrong. This is the sense the runtime never had — every other probe here
        # points where the body already faces, so "which way is still open" could
        # only ever be asked about the half of the world in front of it, and only
        # after it had already stopped. Cheap to read, and the ring closing is
        # what a trap looks like from the inside while there is still a way out.
        observation["radar"] = self._radar(agent, observation)
        self._mark_memory_stops(observation, observation["radar"])
        # Footing reflex (#101): SR56 stood Dufus on unwalkable ground twice — a
        # raised slab, a carport floor with a hole — and every other sense here
        # stayed silent because they all measure AIR. ground_under_feet is the
        # one measurement taken AT the body, and this is the body doing
        # something about it on its own, before the LLM is ever asked
        # ([[architecture_body_writes_no_go]]): step clear, seal the spot on the
        # shared map, and only bother the model when the step itself fails.
        if observation.get("ground_under_feet") is False:
            observation["footing_recovery"] = self._recover_footing(agent, observation)
        # Forward path sense (B7): trace ahead on every moving tick, not just when
        # already wedged — a mobile blocker (someone crossing the path) becomes a
        # fact the LLM can sidestep *before* the collision, and when stuck,
        # whatever is ahead is reported. A stalled order counts too, and used not
        # to: `moving` reads the engine's AI state, a walk that never starts
        # leaves that state idle, and so SR40 spent eight wedged ticks with the
        # trace switched off (#60). Facts only — the decision stays with the LLM.
        stalled = bool((observation.get("last_move") or {}).get("stalled"))
        if moving or stuck or stalled:
            probe_cm = _STUCK_TRACE_CM if (stuck or stalled) else _AHEAD_TRACE_CM
            trace = self._probe_ahead(agent, probe_cm)
            # Width of whatever is ahead, kept for `_seal_dead_end` (#91).
            if trace.get("blocked_fraction") is None:
                self._last_raster.pop(agent_id, None)
            else:
                self._last_raster[agent_id] = float(trace["blocked_fraction"])
            if trace.get("hit"):
                category = _classify_blocker(
                    trace.get("actor_name", ""),
                    trace.get("actor_class", ""),
                    trace.get("signals"),
                )
                distance_cm = float(trace.get("distance_cm", 0.0) or 0.0)
                # #61: EVERY hit is a fact now. The old code only kept the hit when
                # the APC was already stuck/stalled or the thing could move, so in
                # SR45 fifteen of Dufus's hits — a parked car, two shop fronts, a
                # road sign, three crowd figures — were classified and then dropped.
                # A parked vehicle on clear navmesh is exactly the case the user
                # asked for, and it is static by definition. Facts, not blockers
                # ([[feedback_facts_not_blocking]]): the fact always reaches the
                # prompt; what changes with urgency is only whether it is allowed to
                # WAKE cognition, so a wall passed at 4 m does not buy a paid tick.
                fits = trace.get("fits")
                urgent = bool(
                    stuck
                    or stalled
                    or category in _MOBILE_BLOCKERS
                    or distance_cm <= _STANDOFF_CM
                    or fits is False          # #81: the body does not fit — always a decision
                )
                observation["blocker"] = {
                    "category": category,
                    "distance_cm": distance_cm,
                    "actor_name": trace.get("actor_name", ""),
                    "urgent": urgent,
                }
                # #81: the body-box facts, present only when the volume probe ran.
                # A thin ray can say "something ahead" but never "the gap is on
                # your left", which is the fact that ends a wedge loop. SR46:
                # Dufus refused three 9-m patches accurately and kept landing in
                # them, because a 15-m step cannot aim finer than the trap is wide.
                if fits is not None:
                    observation["blocker"]["fits"] = bool(fits)
                    observation["blocker"]["open_columns"] = list(
                        trace.get("open_columns") or [])
                    observation["blocker"]["raster_silent"] = bool(
                        trace.get("raster_silent"))
                if fits is False:
                    # Blocked straight ahead is only half a fact. Without the
                    # other half the only move left is to turn around, which is
                    # what SR49's bounce was made of (#88).
                    openings = self._open_headings(observation["radar"])
                    observation["blocker"]["open_headings"] = openings
                    if openings:
                        logger.info(
                            "[%s] open headings: %s", agent_id,
                            ", ".join(f"{h['heading']} ({h['clearance_cm'] / 100:.1f} m)"
                                      for h in openings))
                    elif observation["radar"]:
                        logger.warning(
                            "[%s] boxed in: all eight headings measured, none has "
                            "room for a step", agent_id)
                    else:
                        # No radar means nothing was measured. Saying "boxed in"
                        # here is what the old sweep did, and it was a lie three
                        # times in SR51 (rule 12).
                        logger.warning(
                            "[%s] open headings unknown — the radar did not run",
                            agent_id)
                    observation["blocker"]["fully_blocked"] = bool(
                        trace.get("fully_blocked"))
                    observation["blocker"]["clearance_cm"] = float(
                        trace.get("clearance_cm", distance_cm) or 0.0)
                # Personal space (B7b): inside the standoff, halt the walk
                # NOW — waiting for the LLM means walking into their face.
                if (moving and category in _MOBILE_BLOCKERS
                        and distance_cm <= _STANDOFF_CM):
                    self.bridge.execute_action(
                        agent.bound_unreal_actor_name, {"type": "stop"}
                    )
                    observation["blocker"]["halted"] = True
                    logger.info(
                        f"[{agent_id}] reflex stop: {category} "
                        f"{distance_cm:.0f} cm ahead "
                        f"(standoff {_STANDOFF_CM:.0f} cm)"
                    )
                fit_note = ""
                if fits is not None:
                    gap = ", ".join(observation["blocker"]["open_columns"]) or "none"
                    fit_note = f" [fits={bool(fits)} open={gap}]"
                logger.info(
                    f"[{agent_id}] blocker: {category} {distance_cm:.0f} cm ahead "
                    f"('{trace.get('actor_name', '')}'){fit_note}"
                    f"{'' if urgent else ' — noted, not waking cognition'}"
                )

        # A completed place survey is durable visual context. While the APC is
        # intentionally settled there, routine pixel changes do not trigger
        # another paid VLM observation. Explicit/manual, schedule, proximity,
        # blocker, and stuck events remain separate transient cognition paths.
        try:
            mapped_schedule = self._existing_schedule_directive(agent, observation)
        except Exception as e:
            logger.warning(f"[{agent_id}] mapped-place cognition gate failed: {e}")
            mapped_schedule = None
        mapped_block = (mapped_schedule or {}).get("block") or {}
        mapped_settled = bool(
            mapped_schedule
            and mapped_schedule.get("status") == "act"
            and mapped_block.get("place")
            and not mapped_schedule.get("transition")
            and not moving
        )
        mapped_schedule_event = bool(
            mapped_schedule
            and (mapped_schedule.get("transition")
                 or mapped_schedule.get("status") == "travel"
                 or (mapped_schedule.get("status") == "act" and moving))
        )
        mapped_visual = None
        col, row = self._cell_col_row(grid)
        if self.place_db and col is not None and mapped_block.get("place"):
            mapped_visual = self.place_db.current_place_image(
                agent_id, col, row, mapped_block["place"]
            )
            if mapped_visual:
                observation["place_image_id"] = mapped_visual["place_image_id"]
        active_non_survey = bool(
            isinstance(active_interrupt, dict) and active_interrupt.get("kind") != "survey"
        )
        mapped_event = force_cognition or nearby_changed or mapped_schedule_event or active_non_survey
        urgent_blocker = bool((observation.get("blocker") or {}).get("urgent"))
        if (mapped_visual and mapped_settled and not stuck
                and not urgent_blocker and not mapped_event):
            agent.mark_ticked(self._agents_dir)
            logger.info(
                f"[{agent_id}] place visual {mapped_visual['place_image_id']} supplies context — "
                "settled routine sampled; VLM sleeping"
            )
            self._pie_activity(agent_id, "state sampled (mapped place)")
            return None

        # An event opened cognition (or the place is not yet durably mapped).
        # Render exactly one routine frame now; no image file exists on the
        # settled mapped-place return path above.
        capture_observation = getattr(self.bridge, "capture_routine_observation", None)
        if callable(capture_observation):
            observation = capture_observation(
                agent.bound_unreal_actor_name, agent_id, self._agents_dir, observation
            )
            if isinstance(active_interrupt, dict):
                observation["active_interrupt"] = active_interrupt

        if not self.bridge.is_scene_changed(agent_id, observation.get("image_path")):
            # The view is unchanged. Skip the LLM if the avatar is still travelling
            # (its own motion will change the view) or to rate-limit an idle agent —
            # but force a fresh decision every Nth stationary tick so a stopped
            # avatar is always re-prompted to move to the next grid/place. Without
            # this a stationary agent freezes: no motion → identical view → LLM
            # skipped → no new move → identical view, forever. A *stuck* agent
            # reports "moving" but isn't progressing, so never skip it — it must
            # re-decide to escape the obstacle. Same for a mobile blocker directly
            # ahead (B7): the agent must re-decide *now* to step around, not after
            # it has already walked through them.
            skips = self._scene_skips.get(agent_id, 0) + 1
            self._scene_skips[agent_id] = skips
            blocked = urgent_blocker
            try:
                schedule = self._existing_schedule_directive(agent, observation)
            except Exception as e:
                logger.warning(f"[{agent_id}] cheap schedule gate failed: {e}")
                schedule = None
            block = (schedule or {}).get("block") or {}
            settled = bool(
                schedule
                and schedule.get("status") == "act"
                and block.get("place")
                and not schedule.get("transition")
                and not moving
            )
            schedule_event = bool(
                schedule
                and (schedule.get("transition")
                     or schedule.get("status") == "travel"
                     or (schedule.get("status") == "act" and moving))
            )
            event = force_cognition or nearby_changed or schedule_event or active_non_survey
            if (settled and not stuck and not blocked and not event):
                agent.mark_ticked(self._agents_dir)
                logger.info(
                    f"[{agent_id}] grid={grid.get('key') if grid else '?'} "
                    f"place={observation.get('place_context', {}) or place or 'unknown'} "
                    "— settled at scheduled place, state sampled; cognition sleeping"
                )
                self._pie_activity(agent_id, "state sampled (settled)")
                return None
            if (not stuck and not blocked and not event
                    and (moving or skips % _STATIONARY_REDECIDE_TICKS != 0)):
                agent.mark_ticked(self._agents_dir)
                reason = "moving" if moving else f"idle {skips}/{_STATIONARY_REDECIDE_TICKS}"
                logger.info(
                    f"[{agent_id}] grid={grid.get('key') if grid else '?'} "
                    f"place={observation.get('place_context', {}) or place or 'unknown'} "
                    f"— scene unchanged ({reason}), skipping LLM"
                )
                self._pie_activity(agent_id, f"OBS skip ({reason})")
                return None
            if stuck:
                why = "stuck on an obstacle"
            elif blocked:
                why = f"{observation['blocker']['category']} directly ahead"
            elif force_cognition:
                why = "manual pulse"
            elif nearby_changed:
                why = "nearby characters changed"
            elif schedule_event:
                why = "schedule or place state changed"
            elif active_non_survey:
                why = "an active interruption needs attention"
            else:
                why = f"stationary {skips} ticks"
            logger.info(
                f"[{agent_id}] {why} — re-deciding to pick a new direction"
            )

        self._scene_skips[agent_id] = 0
        return observation

    def _probe_ahead(self, agent, distance_cm: float) -> dict:
        """One forward probe, normalised — the body-box if available, else the ray.

        #81 replaced the single hip-height ray with a capsule sweep plus a coarse
        raster, but that lives in C++ and only exists once the plugin is rebuilt.
        Until then the old ray still answers, so this returns one shape either way:

            {'hit', 'distance_cm', 'actor_name', 'actor_class', 'signals',
             'fits', 'open_columns', 'fully_blocked', 'clearance_cm'}

        ``fits`` is None when only the ray ran — callers use that to tell "the body
        does not fit" from "we never measured", and must never read None as False.
        The fallback is announced once per run (rule 12): running blind on the old
        probe is a real degradation and must not look like normal operation.
        """
        actor = agent.bound_unreal_actor_name
        volume = getattr(self.bridge, "forward_volume", None)
        if callable(volume) and not self._volume_probe_unavailable:
            try:
                result = volume(actor, distance_cm) or {}
            except Exception as e:
                result = {"error": str(e)}
            if result.get("success") and "fits" in result:
                contact = result.get("contact") or {}
                openings, silent = _open_columns(result)
                # With no sweep contact the nearest raster cell is the honest
                # distance; with neither, nothing was struck at all.
                distance = contact.get("distance_cm")
                if distance is None:
                    distance = result.get("nearest_cm", distance_cm)
                return {
                    "hit": bool(result.get("hit")),
                    "distance_cm": float(distance or 0.0),
                    "actor_name": contact.get("actor_name", ""),
                    "actor_class": contact.get("actor_class", ""),
                    "signals": contact,
                    "fits": bool(result.get("fits")),
                    "open_columns": openings,
                    "raster_silent": silent,
                    "fully_blocked": bool(result.get("fully_blocked")),
                    "clearance_cm": float(result.get("clearance_cm", 0.0) or 0.0),
                    # How much of the raster is solid — the only measurement of
                    # how WIDE the thing is, so it sets how wide a seal is (#91).
                    "blocked_fraction": (
                        None if result.get("blocked_fraction") is None
                        else float(result["blocked_fraction"])),
                }
            self._volume_probe_unavailable = True
            logger.warning(
                "body-box probe (#81) unavailable — falling back to the single "
                f"forward ray for the rest of this run. Engine said: "
                f"{result.get('error') or result}. Rebuild the UnrealMCP plugin to "
                "get 'can I fit' and 'where is the gap'."
            )

        trace = self.bridge.line_trace_forward(actor, distance_cm) or {}
        return {
            "hit": bool(trace.get("hit")),
            "distance_cm": float(trace.get("distance_cm", 0.0) or 0.0),
            "actor_name": trace.get("actor_name", ""),
            "actor_class": trace.get("actor_class", ""),
            "signals": None,
            "fits": None,          # never measured — not the same as "does not fit"
            "open_columns": [],
            "blocked_fraction": None,   # no raster on the ray path (#91)
            "raster_silent": False,
            "fully_blocked": False,
            "clearance_cm": float(trace.get("distance_cm", 0.0) or 0.0),
        }

    def _radar(self, agent, observation: dict,
               distance_cm: float = _RADAR_RANGE_CM) -> list[dict]:
        """Range to the first thing the body cannot pass, on all eight headings (#92).

        One capsule sweep per compass heading, aimed by yaw offset so the body
        never turns — the engine rotates the swept capsule, so every entry is a
        real "would my body fit that way" answer and not a guess from rays.

        Named in COMPASS words, not body-relative ones, because that is the
        vocabulary the APC steers with (#59): "left" changes meaning the moment
        it turns, "north" does not.

        Returned in fixed compass order (N first, clockwise) so the readout is a
        dial the model can compare tick to tick, rather than a list that
        reshuffles whenever the body turns.

        Facts only. A range per heading and whether that sweep ran clear to the
        end of its reach. Nothing here says which way to go, and nothing here
        stops a step ([[feedback_facts_not_blocking]]).
        """
        facing = _yaw_of(observation.get("rotation"))
        if facing is None:
            return []
        ring = self._radar_one_trip(agent, facing, distance_cm)
        if ring is not None:
            # #101: ground_under_feet / nearest_ground are result-level, not
            # per-heading, so they ride the observation rather than the ring.
            ground_facts = self._last_ground.get(agent.agent_id)
            if ground_facts:
                observation.update(ground_facts)
            return ring
        volume = getattr(self.bridge, "forward_volume", None)
        if not callable(volume) or self._volume_probe_unavailable:
            return []
        out: list[dict] = []
        for letter in _RADAR_HEADINGS:
            # Signed shortest turn from the current facing to this heading.
            offset = ((_COMPASS_ABS_YAW[letter] - facing + 180.0) % 360.0) - 180.0
            try:
                result = volume(agent.bound_unreal_actor_name, distance_cm,
                                yaw_offset_deg=offset) or {}
            except Exception as e:
                logger.warning("[%s] radar sweep %s failed: %s",
                               agent.agent_id, letter, e)
                continue
            # `fits` missing means the body-box probe did not run at all. That is
            # not "blocked" — say nothing for this heading rather than report a
            # measurement that was never taken (rule 12).
            if not result.get("success") or result.get("fits") is None:
                continue
            out.append({
                "heading": _COMPASS_LETTER_WORD[letter],
                # Distance to first contact, or the full reach when nothing was
                # struck — the engine reports clearance as exactly that.
                "range_cm": float(result.get("clearance_cm", 0.0) or 0.0),
                "clear_to_end": bool(result.get("fits")),
                "turn_deg": abs(offset),
            })
        return out

    def _radar_one_trip(self, agent, facing: float,
                        distance_cm: float) -> list[dict] | None:
        """The whole ring from one bridge call, or None if the engine cannot (#92).

        Same measurement as the eight-sweep loop below, same units, same shape —
        this is purely the cost. Returning None (never []) is what makes the
        caller fall back: an empty ring is a real answer meaning "nothing was
        measurable", and must not be confused with "this command does not exist".

        Sector 0 is aimed at NORTH rather than at the body, so the ring is
        already in the compass words the APC steers with and does not have to be
        re-labelled when the body turns.
        """
        call = getattr(self.bridge, "radar", None)
        if not callable(call) or self._radar_command_unavailable:
            return None
        # Rotate sector 0 from the body's facing onto north; sectors then run
        # clockwise through _RADAR_HEADINGS exactly.
        to_north = ((_COMPASS_ABS_YAW["N"] - facing + 180.0) % 360.0) - 180.0
        try:
            result = call(agent.bound_unreal_actor_name, distance_cm,
                          sectors=len(_RADAR_HEADINGS),
                          yaw_offset_deg=to_north) or {}
        except Exception as e:
            result = {"error": str(e)}
        sectors = result.get("ring")
        if not result.get("success") or not isinstance(sectors, list):
            self._radar_command_unavailable = True
            self._last_ground.pop(agent.agent_id, None)
            logger.warning(
                "one-trip radar (#92) unavailable — falling back to eight "
                "separate sweeps for the rest of this run. The radar still "
                "works and still sees all eight headings; it just costs eight "
                "round trips instead of one. Engine said: %s. Rebuild the "
                "UnrealMCP plugin to get the fast path.",
                result.get("error") or result)
            return None
        # #101: the ground-column facts live at result level (ground_under_feet,
        # nearest_ground), not per sector, and an un-rebuilt plugin simply omits
        # them — absence means "not measured", never "not walkable" (rule 12).
        if "ground_under_feet" in result:
            ground_facts: dict = {"ground_under_feet": bool(result["ground_under_feet"])}
            nearest = result.get("nearest_ground")
            if isinstance(nearest, dict):
                ground_facts["nearest_ground"] = nearest
            self._last_ground[agent.agent_id] = ground_facts
        else:
            self._last_ground.pop(agent.agent_id, None)
        out: list[dict] = []
        for letter, sector in zip(_RADAR_HEADINGS, sectors):
            if not isinstance(sector, dict) or sector.get("fits") is None:
                continue
            offset = ((_COMPASS_ABS_YAW[letter] - facing + 180.0) % 360.0) - 180.0
            heading = {
                "heading": _COMPASS_LETTER_WORD[letter],
                "range_cm": float(sector.get("clearance_cm", 0.0) or 0.0),
                "clear_to_end": bool(sector.get("fits")),
                "turn_deg": abs(offset),
            }
            # #101: how far the WALKABLE ground goes this way, which can end
            # short of the air the sweep measured (SR56's slab and carport
            # hole were both cases where the air was clear and the ground
            # was not).
            if sector.get("ground_cm") is not None:
                heading["ground_cm"] = float(sector["ground_cm"])
            out.append(heading)
        return out

    def _open_headings(self, radar: list[dict]) -> list[dict]:
        """Which headings have room for a step, read off the radar (#88, #92).

        This used to fire its own four capsule sweeps, and only after the body
        had already failed to fit. The radar has now measured all eight on this
        same tick, so this is a filter over facts already in hand — no extra
        bridge calls, and the half of the compass behind the body is finally in
        the answer.

        Nearest-to-straight-ahead first, because a smaller turn is a cheaper move
        — an ordering, not a recommendation.
        """
        out = [{"heading": h["heading"],
                "clearance_cm": h["range_cm"],
                "turn_deg": h["turn_deg"]}
               for h in radar if h["range_cm"] >= move_plan.MIN_STEP_CM]
        out.sort(key=lambda h: (h["turn_deg"], -h["clearance_cm"]))
        return out

    def _mark_memory_stops(self, observation: dict, ring: list[dict]) -> None:
        """Overlay the shared map on the radar ring: air is not permission (#94).

        SR53 and SR54 each spent a paid decision the same way — the ring said
        "south 20.0 m, room to travel", the order went south, and `move_plan`
        HELD it at zero because refused ground sat directly ahead. The radar was
        honest about air and silent about permission, which is the same class of
        lie #92 was built to kill, one layer up.

        This walks `_scan_ahead` down each measured heading — the identical scan
        the step planner will run if that heading is ordered — and files where
        memory stops the step (`memory_stop_cm`) and why (`memory_reason`).
        Facts only: nothing is removed from the ring and no heading is
        forbidden; the APC that wants the refused ground anyway still walks to
        its edge.
        """
        xyz = _loc_xyz(observation.get("location"))
        if xyz is None:
            return
        for h in ring:
            yaw = _WORD_ABS_YAW.get(h.get("heading"))
            if yaw is None:
                continue
            limit = min(float(h.get("range_cm", 0.0)), move_plan.MAX_STEP_CM)
            if limit <= 0:
                continue
            scan = self._scan_ahead(xyz, yaw, limit)
            if scan["stop_short_cm"] is not None:
                h["memory_stop_cm"] = scan["stop_short_cm"]
                h["memory_reason"] = scan["stop_reason"]

    def _recover_footing(self, agent: Agent, observation: dict) -> dict:
        """Step the body off unwalkable ground, code-side, no LLM call (#101).

        SR56: Dufus stood on a raised slab and in a carport floor's hole, both
        invisible to every other sense because they all measure air. This runs
        the instant ``ground_under_feet`` reads false — a real body steps down
        off a slab on its own, it does not wait for a paid decision to notice
        its feet are wrong. The spot is sealed as a MEASURED no-go patch (same
        write path #91/#95 already use) so the shared map remembers the trap,
        an episode is written, and a lifetime count is kept for the run
        summary. Only a failed step (beyond the reflex's 400 cm reach, or no
        walkable ground found at all) leaves a fact for the prompt — a
        successful one needs no decision, the body already fixed it.

        Returns the outcome dict that also rides into the decision log
        (``footing_recovery``, #101 point 8).
        """
        agent_id = agent.agent_id
        step = getattr(self.bridge, "step_to_ground", None)
        if not callable(step):
            return {"stepped": False, "reason": "step_to_ground not available — rebuild the plugin"}
        try:
            result = step(agent.bound_unreal_actor_name) or {}
        except Exception as e:
            logger.warning("[%s] footing: step_to_ground failed: %s", agent_id, e)
            return {"stepped": False, "reason": str(e)}

        stepped = bool(result.get("stepped"))
        from_xyz = result.get("from")
        distance_cm = result.get("distance_cm")
        outcome: dict = {"stepped": stepped}
        if from_xyz is not None:
            outcome["from"] = from_xyz
        if distance_cm is not None:
            outcome["distance_cm"] = distance_cm

        if not stepped:
            outcome["reason"] = result.get("reason", "")
            nearest = observation.get("nearest_ground")
            if nearest is not None:
                outcome["nearest_ground"] = nearest
            logger.warning("[%s] footing: could not step clear — %s",
                           agent_id, outcome["reason"])
            return outcome

        to_xyz = result.get("to") or {}
        outcome["to"] = to_xyz
        stepped_cm = float(distance_cm or 0.0)

        def _fmt(v) -> str:
            return f"({v.get('x', 0):.0f}, {v.get('y', 0):.0f}, {v.get('z', 0):.0f})" \
                if isinstance(v, dict) else "(?)"

        heading = ""
        if isinstance(from_xyz, dict) and to_xyz:
            dx = to_xyz.get("x", 0.0) - from_xyz.get("x", 0.0)
            dy = to_xyz.get("y", 0.0) - from_xyz.get("y", 0.0)
            if dx or dy:
                heading = _COMPASS_LETTER_WORD.get(
                    yaw_to_compass(math.degrees(math.atan2(dy, dx))), "")
        logger.warning(
            "[%s] footing: stood on unwalkable ground at %s — stepped %.1f m "
            "%sonto walkable ground at %s",
            agent_id, _fmt(from_xyz), stepped_cm / 100.0,
            f"{heading} " if heading else "", _fmt(to_xyz))

        # Seal it exactly like a measured wall (#91/#95): body-scale radius,
        # source="measured" so it merges only with other engine readings and
        # expires like one — the ground may be fixed under it later.
        if self.place_db and isinstance(from_xyz, dict):
            radius_cm = stepped_cm + dead_end.BASE_RADIUS_CM
            self.place_db.refuse_patch(
                agent_id, from_xyz.get("x", 0.0), from_xyz.get("y", 0.0),
                "unwalkable ground", str(observation.get("world_time") or ""),
                radius_cm=radius_cm, source="measured", proofs=1,
            )

        self._episodic(agent_id).record({
            "world_time": observation.get("world_time", ""),
            "grid_cell": _cell_label(observation.get("grid")),
            "event": "footing_recovery",
            "from": from_xyz,
            "to": to_xyz,
            "distance_cm": stepped_cm,
        })
        self._footing_recoveries[agent_id] = self._footing_recoveries.get(agent_id, 0) + 1
        outcome["count"] = self._footing_recoveries[agent_id]
        return outcome

    def _nearby_agent_ids(self, agent_id: str, xyz) -> frozenset[str]:
        """Nearby APC ids from cached transforms; no bridge or model work."""
        if xyz is None:
            return frozenset()
        return frozenset(
            other_id for other_id, pos in self._live_pos.items()
            if other_id != agent_id
            and math.hypot(pos["x"] - xyz[0], pos["y"] - xyz[1]) <= _NEARBY_CHARACTER_CM
        )

    def _existing_schedule_directive(self, agent: Agent,
                                     observation: dict) -> dict | None:
        """Resolve the persisted schedule against current geometry, model-free.

        This is only a cognition gate. It never calls ``ensure_daily_plan`` and
        never wake-seeds a missing place. The full schedule attachment remains
        in the cognition phase, where a missing/new-day plan may be generated.
        """
        world_time = observation.get("world_time", "")
        day = planner.day_of(world_time)
        agenda_doc, source = self._agenda_document(agent, day, generate=False)
        if agenda_doc is None:
            return None
        return self._advance_agenda(agent, observation, agenda_doc, source,
                                    seed_if_unknown=False)

    def _detect_stuck(self, agent_id: str, xyz, moving: bool) -> bool:
        """True when the avatar reports moving but isn't actually advancing.

        Lizard-brain "device driver" robustness: worlds may have imperfect navmesh,
        so an avatar can wedge against an obstacle (a parked van) yet still report
        ai_state="moving". We watch real position delta across ticks; after
        ``_STUCK_TICKS`` no-progress moving ticks the agent is stuck and must
        re-decide. Mirrors explore mode's frontier-failure blocking for the live
        LLM path. Returns False whenever the agent isn't moving or is advancing.
        """
        last = self._last_pos.get(agent_id)
        if xyz is not None:
            self._last_pos[agent_id] = (xyz[0], xyz[1])
        if xyz is None or not moving or last is None:
            self._no_progress[agent_id] = 0
            return False
        moved = math.hypot(xyz[0] - last[0], xyz[1] - last[1])
        if moved >= _STUCK_PROGRESS_CM:
            self._no_progress[agent_id] = 0
            return False
        n = self._no_progress.get(agent_id, 0) + 1
        if n >= _STUCK_TICKS:
            # Flag stuck and reset, so the redirect gets a fresh grace window to
            # take effect before we'd flag again — no per-tick LLM hammering.
            self._no_progress[agent_id] = 0
            return True
        self._no_progress[agent_id] = n
        return False

    def _perceive_and_decide(self, agent: Agent, observation: dict) -> dict | None:
        """Phase 2: Gemini perception → LLM decision.

        Runs in a thread pool so multiple agents can execute this
        concurrently. No bridge calls here — bridge is single-socket.
        """
        agent_id = agent.agent_id

        if observation.get("image_path"):
            seen = self.perceiver.perceive(
                observation["image_path"], observation["known_characters"]
            )
            if seen.get("error"):
                logger.warning(f"[{agent_id}] perception failed: {seen['error']}")
            observation["seen"] = seen
            observation["breadcrumbs"] = self._stamp_footing(
                agent_id, observation.get("grid"), seen)
            self._note_eyes(agent_id, observation.get("location"),
                            _yaw_of(observation.get("rotation")), seen)
            self._save_perception_evidence(agent_id, observation, seen)
            self._record_perception_pair(
                agent_id, observation.get("image_path"), seen,
                location=observation.get("location"),
                yaw=_yaw_of(observation.get("rotation")),
                grid=observation.get("grid"),
                world_time=observation.get("world_time"), context="tick")

            xyz = _loc_xyz(observation.get("location"))
            if xyz and seen.get("landmarks"):
                # Raw sightings → spatial map (for direction-preview in prompts)
                smap = self._spatial_map(agent_id)
                smap.ingest(xyz[0], xyz[1], seen["landmarks"])
                smap.save(self._agents_dir / agent_id / "spatial_map.json")

                # Compass-oriented sightings → PlaceDB
                if self.place_db:
                    grid = observation.get("grid")
                    col, row = self._cell_col_row(grid)
                    yaw = _yaw_of(observation.get("rotation"))
                    if col is not None and yaw is not None:
                        self.place_db.ingest_compass(
                            agent_id, col, row,
                            yaw_to_compass(yaw),
                            seen["landmarks"],
                        )

        # Identity is engine geometry, not a vision guess (#44). Without this the
        # VLM's "unknown person" is all social memory ever receives, so no APC
        # ever recognizes another and every encounter reads as a first meeting.
        self._identify_visible_apcs(agent, observation)
        # What another APC just said is a fact this agent may respond to (#45).
        self._attach_heard_speech(agent, observation)

        # Remember who was seen this tick (named characters → social memory).
        self._record_sightings(agent_id, observation)

        # Surface known people for recall so the decision layer can reason about
        # who this agent has met (e.g. greet someone, seek out a friend). Tag each
        # with recently_greeted (#12.1) so the reaction gate won't re-greet someone
        # just spoken with.
        acquaintances = self._social(agent_id).acquaintances()
        observation["acquaintances"] = self._mark_recent_greetings(
            acquaintances, observation.get("world_time"))
        # Surface the named-place map (nearest first) so the agent can pick a
        # destination by name — walk_to then resolves it to a location (#1).
        observation["known_places"] = self.known_places(observation.get("location"))[:8]
        # Surface the most relevant past episodes (recency ⊕ same place ⊕ known
        # faces) so overnight runs recall more than the flat 30-item window.
        place_list = observation.get("place") or []
        observation["recent_episodes"] = self._episodic(agent_id).relevant(
            n=5,
            current_cell=(observation.get("grid") or {}).get("key"),
            current_place=place_list[0] if place_list else None,
            known_names=[a["name"] for a in acquaintances],
        )

        # Sequencer: give the agent a routine to follow instead of pure reaction.
        # ensure_daily_plan generates the day's schedule once (idempotent within a
        # sim-day), then step() answers "what should I be doing now?" — travel to
        # the scheduled place, act here, or idle. The directive grounds the
        # decision prompt; the LLM still chooses the action.
        self._attach_schedule(agent, observation)

        # Travel ticks get a top-down route map (#6b/WP5): the corridor between
        # here and the scheduled destination, as facts + a rendered image the
        # multimodal decision call reads. Travel-only bounds the token cost.
        sched = observation.get("schedule") or {}
        if sched.get("status") == "travel" and sched.get("place"):
            try:
                route = self.route_map_for(agent_id, sched["place"], observation)
                if route:
                    observation["route_map"] = route
            except Exception as e:
                logger.warning(f"[{agent_id}] route map failed: {e}")

        # Authoritative survey verdict for the cell underfoot (#40), so cognition
        # cannot invent missing headings for an already-surveyed cell.
        survey_fact = self._cell_survey_fact(agent, observation)
        if survey_fact is not None:
            observation["cell_survey"] = survey_fact

        memories = self.memory.get_relevant_memories(agent_id)
        return self.llm.decide(agent, observation, memories)

    def _attach_schedule(self, agent: Agent, observation: dict) -> None:
        """Compute the sequencer directive for this tick and attach it to the
        observation as ``observation["schedule"]`` (consumed by the decision
        prompt). Pure per-agent file writes (the day's plan), safe in the
        parallel decide phase. Degrades silently — a planning hiccup must never
        break a tick."""
        try:
            world_time = observation.get("world_time", "")
            day = planner.day_of(world_time)
            agenda_doc, source = self._agenda_document(agent, day, generate=True)
            if agenda_doc is None:
                observation["schedule"] = None
                return
            schedule = agenda.to_schedule(agenda_doc)
            self._validate_schedule(agent, schedule, planner.day_of(world_time))
            # Geometric "am I already there?" beats name matching: on a fresh
            # world nothing is named yet, and the old name-only check sent an
            # agent hunting for the place it was standing at (Maren's wake bug).
            # (Normally the spool-up already consumed the wake seed at the true
            # spawn — this is the no-spool-up fallback.) Only a step that had
            # real position data consumes the once-per-run seed chance.
            wake = agent.agent_id not in self._wake_stepped
            if (_loc_xyz(observation.get("location")) is not None
                    and self._cell_col_row(observation.get("grid"))[0] is not None):
                self._wake_stepped.add(agent.agent_id)
            observation["schedule"] = self._advance_agenda(
                agent, observation, agenda_doc, source, seed_if_unknown=wake)
            self._attach_route_progress(agent.agent_id, observation)
        except Exception as e:
            logger.warning(f"[{agent.agent_id}] schedule step failed: {e}")
            observation["schedule"] = None

    def _agenda_document(self, agent: Agent, day: str,
                         *, generate: bool) -> tuple[dict | None, str]:
        """Choose authored agenda first, preserving generated schedules as fallback."""
        if isinstance(getattr(agent, "authored_agenda", None), dict):
            return agent.authored_agenda, "authored"
        schedule_day = getattr(agent, "daily_schedule_day", "")
        schedule_blocks = getattr(agent, "daily_schedule_blocks", None) or []
        if schedule_day == day and schedule_blocks:
            return agenda.from_schedule(schedule_blocks), "generated"
        if not generate:
            return None, "generated"
        ask = getattr(self.llm, "ask", None)
        schedule = planner.ensure_daily_plan(
            agent, day,
            ask=(lambda prompt: ask(agent, prompt)) if ask else None,
            agents_dir=self._agents_dir,
        )
        return agenda.from_schedule(schedule), "generated"

    @staticmethod
    def _agenda_execution_for(agent) -> dict:
        """Read agenda state from a real Agent or a legacy duck-typed caller."""
        execution = getattr(agent, "agenda_execution", None)
        if isinstance(execution, dict):
            return execution
        fallback = getattr(agent, "_agenda_execution", None)
        return fallback if isinstance(fallback, dict) else {}

    def _store_agenda_execution(self, agent, execution: dict) -> None:
        """Persist through Agent when available; keep legacy stubs in memory."""
        setter = getattr(agent, "set_agenda_execution", None)
        if callable(setter):
            setter(execution, self._agents_dir)
        else:
            agent._agenda_execution = copy.deepcopy(execution)

    def _sync_agenda_goal(self, agent, goal: str) -> None:
        """Keep legacy current_goal aligned without requiring the full Agent API."""
        if not goal or getattr(agent, "current_goal", None) == goal:
            return
        setter = getattr(agent, "set_goal", None)
        if callable(setter):
            setter(goal, self._agents_dir)
        else:
            agent.current_goal = goal

    def _advance_agenda(self, agent: Agent, observation: dict, agenda_doc: dict,
                        source: str, *, seed_if_unknown: bool) -> dict:
        """Apply grounded time/place/interrupt facts and return a legacy directive."""
        world_time = str(observation.get("world_time") or self.world_clock.now_text())
        minute = planner.minute_of_day(world_time)
        day = planner.day_of(world_time)
        checked_task_id = ""
        at_place = None
        result = None
        tasks = agenda_doc.get("tasks", [])
        for _ in range(len(tasks) + 1):
            result = agenda.advance(
                agenda_doc, self._agenda_execution_for(agent),
                day=day, source=source, minute=minute, world_time=world_time,
                active_interrupt=getattr(agent, "active_interrupt", None),
                last_interrupt=getattr(agent, "last_interrupt", None),
                at_place_task_id=checked_task_id, at_place=at_place,
            )
            self._store_agenda_execution(agent, result["execution"])
            task = result.get("active_task")
            if task is None or task["id"] == checked_task_id:
                break
            checked_task_id = task["id"]
            block = agenda.to_schedule({"tasks": [task]})[0]
            at_place = self._at_scheduled_place(
                agent.agent_id, block, observation,
                seed_if_unknown=seed_if_unknown,
            )

        facts = (result or {}).get("context") or agenda.context(
            agenda_doc, self._agenda_execution_for(agent),
            active_interrupt=getattr(agent, "active_interrupt", None))
        observation["agenda"] = facts
        task = (result or {}).get("active_task")
        if task is None:
            right_now = facts.get("right_now") or {}
            right_now["current_place"] = ((observation.get("place_context") or {}).get("name")
                                          or next(iter(observation.get("place") or []), None))
            next_task = facts.get("next")
            if next_task is not None:
                activity = f"wait for {next_task['objective']} at {next_task['activates_at']}"
                self._sync_agenda_goal(agent, activity)
                hold_place = str(right_now.get("current_place") or "")
                directive = {
                    "block": None,
                    "activity": activity,
                    "place": hold_place,
                    "status": "act",
                    "transition": agent.last_activity != activity,
                    "intent": (f"Your next agenda task begins at {next_task['activates_at']}: "
                               f"{next_task['objective']}. Stay here until then; do not begin "
                               "free-goal work."),
                }
                directive["agenda_status"] = "waiting"
            else:
                directive = planner.step([], minute, prev_activity=agent.last_activity)
                directive["agenda_status"] = "idle"
            directive["agenda"] = copy.deepcopy(facts)
            return directive

        block = agenda.to_schedule({"tasks": [task]})[0]
        place_context = observation.get("place_context") or {}
        place_names = observation.get("place") or []
        current_place = place_context.get("name") or (place_names[0] if place_names else None)
        directive = planner.step(
            [block], minute, current_place=current_place,
            prev_activity=agent.last_activity, at_place=at_place,
        )
        current = facts.get("right_now") or {}
        self._sync_agenda_goal(agent, task["objective"])
        current["current_place"] = current_place
        current["destination"] = task.get("place") or None
        current["arrival_verdict"] = (
            "at_place" if at_place is True else
            "not_at_place" if at_place is False else "unknown")
        directive["task_id"] = task["id"]
        directive["completion"] = copy.deepcopy(task["completion"])
        directive["agenda_status"] = current.get("status", "active")
        directive["agenda"] = copy.deepcopy(facts)
        return directive

    def _attach_route_progress(self, agent_id: str, observation: dict) -> None:
        """Describe progress toward the remembered place on a travel tick.

        Attaches place, heading, distance and engine path status to the schedule
        when the previous tick's cached route is for this directive's place —
        pure legibility for the prompt and the decision log; the LLM contract
        (walk_to target_location) is unchanged. ``delta_cm`` is the change in
        straight-line distance to the route's final destination since the last
        travel tick — positive means the agent moved farther away — computed
        from ``route["last_distance_cm"]``, which this call updates for the
        next tick. ``None`` on the first travel tick of a route (no prior
        distance to compare against) and jitter below ``_PROGRESS_NOISE_CM`` is
        reported as ``0`` rather than false regression.
        """
        directive = observation.get("schedule") or {}
        route = self._routes.get(agent_id)
        if (directive.get("status") != "travel" or not route
                or route["destination"] != directive.get("place")):
            return
        center = route["target_xy"]
        xyz = _loc_xyz(observation.get("location"))
        heading = None
        if center is not None and xyz is not None:
            dx, dy = center[0] - xyz[0], center[1] - xyz[1]
            if dx or dy:
                heading = yaw_to_compass(math.degrees(math.atan2(dy, dx)))
        delta_cm = None
        if xyz is not None:
            tx, ty = route["target_xy"]
            distance_cm = math.hypot(tx - xyz[0], ty - xyz[1])
            last_distance_cm = route.get("last_distance_cm")
            if last_distance_cm is not None:
                raw_delta = distance_cm - last_distance_cm
                delta_cm = 0.0 if abs(raw_delta) < _PROGRESS_NOISE_CM else raw_delta
            route["last_distance_cm"] = distance_cm
        directive["route"] = {"to_place": route["destination"], "heading": heading,
                              "distance_m": round(distance_cm / 100.0, 1) if xyz else None,
                              "path_status": route.get("path_status"),
                              "delta_cm": delta_cm}
        agenda_facts = observation.get("agenda") or {}
        right_now = agenda_facts.get("right_now") or {}
        right_now["route"] = copy.deepcopy(directive["route"])
        nested = directive.get("agenda") or {}
        nested_right_now = nested.get("right_now") or {}
        nested_right_now["route"] = copy.deepcopy(directive["route"])

    def _place_resolves(self, agent_id: str, name: str) -> bool:
        """True when ``name`` reaches a real endpoint for ``agent_id``.

        The same chain ``_resolve_place_endpoint``/``_at_scheduled_place`` walk —
        community-named cell, else an owned place preferring this agent's own
        entries. Kept in one place so the start-time preflight and the plan-time
        check can never disagree about what "resolves" means.
        """
        if self.place_db is None or not name:
            return False
        return (self.place_db.find_named_cell(name) is not None
                or self.place_db.find_owned_place(
                    name, preferred_owner=agent_id) is not None)

    def _validate_schedule(self, agent: Agent, schedule: list | None, day: str) -> list:
        """Fail loud at plan time: warn for schedule blocks whose place resolves
        to nothing in PlaceDB (WP6 D5) — the agent will hunt for it; the fix is
        authoring it in places.json. Resolves through the same chain as
        ``_at_scheduled_place`` (community name, else owned place). Runs at
        most once per (agent_id, day); returns the bad blocks (for tests),
        ``[]`` when cached or nothing to check.

        This is the *generated*-schedule net. An authored agenda is checked
        before the run instead — see ``preflight_places`` (#63): a warning that
        arrives on the tick that needs the place has already cost the run.
        """
        key = (agent.agent_id, day)
        if key in self._validated_plans or self.place_db is None:
            return []
        self._validated_plans.add(key)
        bad = []
        for block in schedule or []:
            name = str(block.get("place") or "").strip()
            if not name or self._place_resolves(agent.agent_id, name):
                continue
            bad.append(block)
            logger.warning(
                f"[{agent.agent_id}] schedule {block.get('start')}-{block.get('end')} "
                f"'{block.get('activity')}' place '{name}' resolves to NOTHING — "
                f"agent will hunt; author it in places.json")
        return bad

    def preflight_places(self, agents: list | None = None) -> list[dict]:
        """Every agenda destination that resolves to nothing, checked before the
        run starts (#63).

        ``_validate_schedule`` already knew how to spot these, but it runs inside
        the tick — so the warning lands in the log on the tick that needed the
        place, by which time the APC is already hunting and the run is already
        spent. SR-era example: Maren's 18:00 task names "Sheriff's office" while
        the surveyed cell is called "sheriff station square", so the task had no
        destination at all and nothing said so until it mattered.

        Reads the *authored* agenda only (``generate=False``) — no LLM call, so
        this is safe on the start path. Returns one row per bad task::

            {"agent_id", "task_id", "start", "end", "place", "objective"}

        An empty list means every destination named by every active agenda
        resolves today.
        """
        rows: list[dict] = []
        if self.place_db is None:
            return rows
        for agent in (agents if agents is not None else self.agents.values()):
            if not agent.is_active:
                continue
            document, _ = self._agenda_document(agent, "Day 1", generate=False)
            if document is None:
                continue
            for task in document.get("tasks", []):
                name = str(task.get("place") or "").strip()
                if not name or self._place_resolves(agent.agent_id, name):
                    continue
                rows.append({"agent_id": agent.agent_id, "task_id": task.get("id", ""),
                             "start": task.get("start", ""), "end": task.get("end", ""),
                             "place": name, "objective": task.get("objective", "")})
                logger.error(
                    f"[{agent.agent_id}] PREFLIGHT: task '{task.get('id')}' "
                    f"({task.get('start')}-{task.get('end')}) place '{name}' resolves to "
                    f"NOTHING — this APC will hunt for it. Name the cell or author it "
                    f"in places.json before relying on this run.")
        return rows

    def preflight_duplicate_places(self) -> list[dict]:
        """One physical place recorded as two owned rows, found before the run (#75).

        The companion to ``preflight_places``: that one catches a name resolving
        to *nothing*, this one catches a name resolving to *two things*. Both are
        the same class of fault — the map disagreeing with the world — and both
        were previously only discoverable by reading a finished run's log.

        Two rows are the same place when one owner gives the same name to two
        spots whose extent boxes overlap. That is not a judgement call: the boxes
        are how "am I there?" is already answered, so two overlapping boxes mean
        an APC is inside both at once. Rows that merely share a name across a real
        distance are two genuinely different places and are left alone.

        The surviving row is the authored one where there is one — ``places.json``
        is ground truth and a runtime observation must never overwrite it — else
        the oldest, so a name keeps meaning what it first meant. Returns one row
        per merge ``{"owner", "name", "kept", "dropped", "gap_cm"}``; empty when
        the map is clean.
        """
        merges: list[dict] = []
        if self.place_db is None:
            return merges

        def _anchor(place):
            center = self.world_grid.cell_center(place["col"], place["row"])
            return None if center is None else (center[0] + place["dx"],
                                                center[1] + place["dy"])

        by_name: dict[tuple[str, str], list[dict]] = {}
        for place in self.place_db.all_owned_places():
            by_name.setdefault(
                (place["owner"], str(place["name"]).strip().lower()), []).append(place)

        for (owner, _), group in by_name.items():
            if len(group) < 2:
                continue
            # Authored first, then oldest — the survivor is decided before any
            # comparison, so which row wins never depends on iteration order.
            group.sort(key=lambda p: (0 if p.get("source") == "authored" else 1,
                                      str(p.get("created_at") or ""),
                                      p["col"], p["row"]))
            keeper, keep_at = group[0], _anchor(group[0])
            if keep_at is None:
                continue
            for other in group[1:]:
                spot = _anchor(other)
                if spot is None:
                    continue
                half = (float(keeper.get("extent_cm") or PLACE_EXTENT_CM)
                        + float(other.get("extent_cm") or PLACE_EXTENT_CM)) / 4.0
                if abs(spot[0] - keep_at[0]) > half or abs(spot[1] - keep_at[1]) > half:
                    continue                      # genuinely a different place
                gap = math.hypot(spot[0] - keep_at[0], spot[1] - keep_at[1])
                if not self.place_db.remove_owned_place(
                        owner, other["col"], other["row"], other["name"]):
                    continue
                merges.append({"owner": owner, "name": keeper["name"],
                               "kept": f"{keeper['col']},{keeper['row']}",
                               "dropped": f"{other['col']},{other['row']}",
                               "gap_cm": round(gap, 1)})
                logger.warning(
                    "[%s] PREFLIGHT: '%s' was recorded twice — cells (%s,%s) and "
                    "(%s,%s), anchors %.0f cm apart, boxes overlapping. Kept the %s "
                    "row at (%s,%s); dropped the other.",
                    owner, keeper["name"], keeper["col"], keeper["row"],
                    other["col"], other["row"], gap,
                    keeper.get("source") or "oldest", keeper["col"], keeper["row"])
        return merges

    def _wake_directive(self, agent: Agent, loc, grid: dict | None,
                        world_time: str) -> dict | None:
        """Sequencer directive for the spool-up wake, at the true spawn spot.

        Runs BEFORE the orient LLM call can move the agent: generates the
        day's schedule, seeds a first-time scheduled place at the spawn
        position (the once-per-run ``seed_if_unknown``), and returns
        ``planner.step``'s directive so the wake prompt can state with ground
        truth whether the agent is already where it should be. Without this,
        the orient prompt asked the LLM to guess — Maren guessed "walk to the
        truck" while standing next to it, and the late per-tick seed then
        stamped her place mid-walk (SR2). Returns None on any failure (the
        wake prompt falls back to its generic guidance).
        """
        try:
            day = planner.day_of(world_time)
            agenda_doc, source = self._agenda_document(agent, day, generate=True)
            if agenda_doc is None:
                return None
            schedule = agenda.to_schedule(agenda_doc)
            self._validate_schedule(agent, schedule, planner.day_of(world_time))
            obs = {"location": loc, "grid": grid, "world_time": world_time}
            seed = agent.agent_id not in self._wake_stepped
            if (_loc_xyz(loc) is not None
                    and self._cell_col_row(grid)[0] is not None):
                self._wake_stepped.add(agent.agent_id)
            return self._advance_agenda(
                agent, obs, agenda_doc, source, seed_if_unknown=seed)
        except Exception as e:
            logger.warning(f"[{agent.agent_id}] wake directive failed: {e}")
            return None

    def _at_scheduled_place(self, agent_id: str, block: dict | None,
                            observation: dict, seed_if_unknown: bool = False) -> bool | None:
        """Is the agent physically at the active block's place? (None = unknown.)

        Resolves the same place and square extent as walk_to. Crossing a survey
        district boundary does not establish arrival at a destination.

        ``seed_if_unknown`` (the agent's first schedule step of a run — wake):
        if the place resolves to nothing at all, it is created as the agent's
        own place cell centered where the agent stands. The editor placement
        is the agent's day-start spot by convention, so "wake at your stall"
        works on a fresh world instead of sending the agent off hunting for a
        name no one has recorded yet (first-time place-cell initialization).
        """
        name = str((block or {}).get("place") or "").strip()
        if not name or self.place_db is None:
            return None
        xyz = _loc_xyz(observation.get("location"))
        col, row = self._cell_col_row(observation.get("grid"))
        if xyz is None:
            return None

        end = self._resolve_place_endpoint(agent_id, name)
        if end is None:
            if not seed_if_unknown or col is None:
                return None
            center = self.world_grid.cell_center(col, row)
            if center is None:
                return None
            if self.place_db.add_owned_place(agent_id, col, row, name,
                                             dx=xyz[0] - center[0],
                                             dy=xyz[1] - center[1],
                                             source="wake-seed"):
                # With a places.json the seed is a fallback that shouldn't fire:
                # an unresolvable scheduled place likely means it wasn't authored.
                log = logger.warning if self._manifest_present else logger.info
                log(f"[{agent_id}] wake: seeded own place cell '{name}' "
                    f"({PLACE_EXTENT_CM / 100:.0f} m box) at current spot "
                    f"({col},{row})"
                    + (" — despite places.json; place not authored?"
                       if self._manifest_present else ""))
                return True
            return None
        return route_planner.at_place(end, (xyz[0], xyz[1]))

    def _act_agent(self, agent: Agent, decision, observation: dict | None) -> dict:
        """Phase 3: validate decision, execute in Unreal, persist memory."""
        agent_id = agent.agent_id
        act_started = time.monotonic()

        if observation is None:
            return {"agent_id": agent_id, "action": "idle", "reason": "scene_unchanged"}

        if isinstance(decision, Exception):
            logger.error(f"[{agent_id}] LLM phase exception: {decision}")
            decision = None

        if not decision:
            logger.warning(f"[{agent_id}] No decision - idling")
            agent.mark_ticked(self._agents_dir)
            self._pie_activity(agent_id, "OBS fire -> no decision (idle)")
            return {"agent_id": agent_id, "action": "idle", "reason": "no_decision"}

        action = validate(agent, decision, observation)
        if not action:
            agent.mark_ticked(self._agents_dir)
            self._pie_activity(agent_id, "OBS fire -> invalid decision (idle)")
            return {"agent_id": agent_id, "action": "idle", "reason": "validation_failed"}

        action = self._bound_at_place_movement(agent, action, observation)

        # Rulings about ground resolve here, against the grid — they change what
        # the map offers, never where the body may go.
        verdict = self._apply_cell_verdict(agent, action, observation)
        if verdict is not None:
            action = verdict

        action, pending = self._resolve_survey_here(agent, action, observation)
        if pending:
            # A newly activated survey has a deliberately durable handoff tick.
            # Its persisted active/preemptible record is visible to operator/API
            # requests before any bridge command locks it. The next pulse runs
            # the headings without asking again. The decision is logged first —
            # SR39's three surveys were the model's own calls, but this early
            # return skipped the log and left them looking like code seizing the
            # tick, which is the exact confusion #57 set out to end.
            observation["_thought"] = decision.get("thought_summary")
            self.memory.record(
                agent_id=agent_id, observation=observation, action=action,
                result={"status": "survey_pending",
                        "interrupt_id": pending["interrupt_id"]},
                memory_update=decision.get("memory_update"),
                importance=float(decision.get("importance", 0.5)),
                timing=observation.get("_timing"),
            )
            agent.mark_ticked(self._agents_dir)
            self._pie_activity(agent_id, "survey_here accepted -> dispatching")
            return {"agent_id": agent_id, "action": "survey_pending",
                    "sweep": True, "interrupt_id": pending["interrupt_id"]}

        survey_action = bool(action.get("_survey_interrupt_id"))
        if survey_action:
            agent.set_active_interrupt_preemptible(False, self._agents_dir)

        result = self._execute_world_action(agent, action, observation)
        self._note_survey_travel_result(agent_id, action, result)
        self._note_movement_order(agent_id, action, observation)
        self._mark_first_walk_accepted(agent_id, action, result)
        self._apply_task_completion_confirmation(
            agent, decision, action, result, observation)
        timing = observation.setdefault("_timing", {})
        timing["act_ms"] = round((time.monotonic() - act_started) * 1000.0, 3)
        timing.update(self._movement_timing_snapshot(agent_id))
        status = result.get("status") or result.get("success")
        # Show the movement itself in PIE, not just the action name — the whole
        # SR34 direction bug was invisible while watching the sim run.
        # No previous position here: it is already advanced to this tick's, and
        # the achieved displacement belongs to the log, not the live line.
        self._pie_activity(agent_id, movement_summary(
            movement_trace(observation, action), action.get("type"), str(status),
        ))

        # Name the place if the LLM provided one.
        self._record_place(agent_id, observation.get("location"), decision.get("place"))

        if action.get("type") == "speak_to":
            agent.mark_spoke(self._agents_dir)
            self._record_interactions(agent_id, observation)
            self._record_utterance(agent, action, observation)

        self._ground_survey_narration(agent, decision, action, result, observation)

        observation["_thought"] = decision.get("thought_summary")
        self.memory.record(
            agent_id=agent_id,
            observation=observation,
            action=action,
            result=result,
            memory_update=decision.get("memory_update"),
            importance=float(decision.get("importance", 0.5)),
            timing=timing,
        )
        self._record_episode(agent_id, observation, action, result)
        # Remember the scheduled activity this tick so next tick's sequencer can
        # detect a block boundary (e.g. noon: "sell veg" -> "have lunch").
        sched = observation.get("schedule")
        if sched is not None:
            agent.set_last_activity(sched.get("activity", ""), self._agents_dir)
        agent.mark_ticked(self._agents_dir)

        return {
            "agent_id": agent_id,
            "thought":  decision.get("thought_summary"),
            "action":   action,
            "result":   result,
            "grid":     observation.get("grid"),
            "place":    observation.get("place"),
        }

    def _apply_task_completion_confirmation(self, agent: Agent, decision: dict,
                                            action: dict, result: dict,
                                            observation: dict) -> bool:
        """Accept bounded model evidence only for the exact active opt-in task."""
        claim = decision.get("task_completion")
        if claim is None:
            return False
        if not isinstance(claim, dict):
            logger.warning("[%s] ignored malformed task_completion", agent.agent_id)
            return False
        right_now = (observation.get("agenda") or {}).get("right_now") or {}
        task_id = str(claim.get("task_id") or "").strip()
        statement = str(claim.get("evidence") or "").strip()
        completion_type = (right_now.get("completion") or {}).get("type")
        if (claim.get("confirmed") is not True or not task_id or not statement
                or task_id != right_now.get("task_id")
                or right_now.get("status") != "active"
                or completion_type != "time_or_llm_confirmed"
                or (right_now.get("place")
                    and right_now.get("arrival_verdict") != "at_place")
                or isinstance(agent.active_interrupt, dict)):
            logger.warning(
                "[%s] ignored out-of-contract task completion for %r",
                agent.agent_id, task_id,
            )
            return False
        result_status = str(result.get("status") or "").strip().lower()
        action_succeeded = (
            not result.get("error")
            and result.get("success") is not False
            and (result.get("success") is True
                 or result_status in {"accepted", "success", "ok"})
        )
        if not action_succeeded:
            logger.warning(
                "[%s] task %s completion withheld because action did not succeed",
                agent.agent_id, task_id,
            )
            return False

        world_time = str(observation.get("world_time") or self.world_clock.now_text())
        day = planner.day_of(world_time)
        agenda_doc, source = self._agenda_document(agent, day, generate=False)
        if agenda_doc is None:
            return False
        completed = agenda.advance(
            agenda_doc, self._agenda_execution_for(agent),
            day=day, source=source,
            minute=planner.minute_of_day(world_time), world_time=world_time,
            active_interrupt=agent.active_interrupt,
            last_interrupt=agent.last_interrupt,
            llm_confirmed_task_id=task_id,
            llm_confirmation_evidence={
                "statement": statement[:240],
                "action_type": str(action.get("type") or ""),
                "action_result": result_status or "success",
            },
        )
        state = next((item for item in completed["execution"].get("tasks", [])
                      if item.get("task_id") == task_id), None)
        if not state or state.get("status") != "completed":
            return False
        self._store_agenda_execution(agent, completed["execution"])
        observation["agenda"] = completed["context"]
        if isinstance(observation.get("schedule"), dict):
            observation["schedule"]["agenda"] = copy.deepcopy(completed["context"])
        logger.info("[%s] agenda task %s completed by bounded model evidence",
                    agent.agent_id, task_id)
        return True

    def _bound_at_place_movement(self, agent: Agent, action: dict,
                                 observation: dict) -> dict:
        """Keep freeform roaming inside the place where the schedule says to act.

        The LLM may choose ``wander`` to perform an activity such as "wander the
        village square". A raw wander is a 15 m forward step and can leave the
        place immediately (SR11). Convert it to a concrete target clamped inside
        the community cell or owned-place box. Named travel and actor approaches
        remain unchanged.
        """
        sched = observation.get("schedule") or {}
        if sched.get("status") != "act" or not sched.get("place"):
            return action
        if not (action.get("type") == "wander"
                or (action.get("type") == "walk_to" and action.get("direction"))):
            return action

        xyz = _loc_xyz(observation.get("location"))
        desired = self._direction_target(observation, action.get("direction") or "forward")
        end = self._resolve_place_endpoint(agent.agent_id, sched["place"])
        if xyz is None or desired is None or end is None:
            return {"type": "idle"}

        cx, cy = end["xy"]
        extent = float(end.get("extent_cm") or 0.0)
        half = (extent / 2.0 if extent > 0 else self.world_grid.cell_size / 2.0)
        safe_half = max(half - _PLACE_ROAM_MARGIN_CM, 0.0)
        tx = min(max(desired[0], cx - safe_half), cx + safe_half)
        ty = min(max(desired[1], cy - safe_half), cy + safe_half)

        # At an edge, clamping can produce the current point. Turn back toward
        # the anchor so repeated wander decisions cannot wedge on the boundary.
        if math.hypot(tx - xyz[0], ty - xyz[1]) < 100.0:
            tx, ty = cx, cy
        return {"type": "walk_to", "location": [tx, ty, xyz[2]]}

    def _attach_nearby_characters(self, observations: dict[str, dict | None]) -> None:
        """Attach deterministic APC proximity facts before parallel LLM work.

        Vision remains the authority for line of sight. This engine-neutral
        position fact prevents a small/far character missed by the VLM from
        becoming completely nonexistent to the decision layer.
        """
        for agent_id, observation in observations.items():
            if observation is None:
                continue
            here = _loc_xyz(observation.get("location"))
            if here is None:
                continue
            nearby = []
            for other_id, pos in self._live_pos.items():
                if other_id == agent_id:
                    continue
                distance = math.hypot(pos["x"] - here[0], pos["y"] - here[1])
                if distance <= _NEARBY_CHARACTER_CM:
                    other = self.agents.get(other_id)
                    nearby.append({"name": getattr(other, "display_name", other_id),
                                   "distance_cm": round(distance, 1)})
            observation["nearby_characters"] = sorted(nearby, key=lambda x: x["distance_cm"])

    def _resolve_place_endpoint(self, agent_id: str, name: str) -> dict | None:
        """Resolve a place name to a travel endpoint, or None if unknown.

        Prefer a specific authored or remembered place over a district label.
        Community-only names approach the survey stand point (center for old
        surveys) with a place-sized extent, never whole-district arrival. Returns
        ``{"cell": (c, r), "xy": (x, y), "extent_cm": float}``.
        """
        if self.place_db is None:
            return None

        owned = self.place_db.find_owned_place(name, preferred_owner=agent_id)

        # The owned store already ranks authored, learned and wake-seeded
        # records. Use that concrete place before a broad community label.
        if owned is not None:
            endpoint = self._owned_place_endpoint(owned)
            if endpoint is not None:
                return endpoint

        cell = self.place_db.find_named_cell(name)
        if cell is not None:
            center = self.world_grid.cell_center(*cell)
            if center is not None:
                place = self.place_db.get_place(*cell) or {}
                if place.get("stand_x") is not None and place.get("stand_y") is not None:
                    center = (float(place["stand_x"]), float(place["stand_y"]))
                return {"cell": cell, "xy": center, "extent_cm": PLACE_EXTENT_CM,
                        "kind": "community", "name": place.get("name") or name}
        return None

    def _owned_place_endpoint(self, owned: dict) -> dict | None:
        center = self.world_grid.cell_center(owned["col"], owned["row"])
        if center is None:
            return None
        logger.info(
            f"Resolved owned place '{owned['name']}' ({owned['owner']}, "
            f"{owned.get('source') or 'runtime'}) -> cell "
            f"({owned['col']},{owned['row']}) offset ({owned['dx']:.0f},{owned['dy']:.0f})"
        )
        return {"cell": (owned["col"], owned["row"]),
                "xy": (center[0] + owned["dx"], center[1] + owned["dy"]),
                "extent_cm": float(owned.get("extent_cm") or PLACE_EXTENT_CM),
                "kind": "owned", "name": owned["name"]}

    def _resolve_place_target(self, agent_id: str, name: str, observation: dict) -> list[float] | None:
        """Resolve a place name to a walk target ``[x, y, z]``, or None.

        The endpoint's world position with the agent's current z kept, so it
        stays on the ground plane. Returns None when the name is unknown —
        callers fall back to the bridge's graceful idle.
        """
        end = self._resolve_place_endpoint(agent_id, name)
        if end is None:
            return None
        xyz = _loc_xyz(observation.get("location"))
        z = xyz[2] if xyz else 0.0
        return [end["xy"][0], end["xy"][1], z]

    def known_places(self, location) -> list[dict]:
        """The named-place map relative to ``location`` — nearest first.

        Each entry: ``{"name", "bearing", "distance_m", "col", "row"}`` where
        bearing is a compass label (N..NW) from the agent toward the place and
        distance is in meters. APC-owned place cells (#11.2) are included too,
        positioned at their community anchor + XY offset and carrying an extra
        ``"owner"`` key. This is the "map" an agent consults — it answers
        *what places exist and roughly which way* before any routing. Returns []
        with no PlaceDB, an unbounded grid, or no location.
        """
        if self.place_db is None:
            return []
        xyz = _loc_xyz(location)
        if xyz is None:
            return []
        x, y = xyz[0], xyz[1]
        out: list[dict] = []

        def _entry(place, px, py, **extra):
            dx, dy = px - x, py - y
            return {
                "name": place["name"],
                "bearing": yaw_to_compass(math.degrees(math.atan2(dy, dx))),
                "distance_m": math.hypot(dx, dy) / 100.0,
                "col": place["col"],
                "row": place["row"],
                **extra,
            }

        for place in self.place_db.all_named_places():
            center = self.world_grid.cell_center(place["col"], place["row"])
            if center is None:
                continue
            out.append(_entry(place, center[0], center[1]))
        for place in self.place_db.all_owned_places():
            center = self.world_grid.cell_center(place["col"], place["row"])
            if center is None:
                continue
            out.append(_entry(place, center[0] + place["dx"], center[1] + place["dy"],
                              owner=place["owner"]))
        out.sort(key=lambda p: p["distance_m"])
        return out

    def route_map_for(self, agent_id: str, destination_name: str, observation: dict) -> dict | None:
        """Top-down route map facts + rendered image for a travel tick (#6b/WP5).

        Resolves the destination through the same chain as walk_to (community
        name first, then this agent's owned places), locates the agent's current
        cell, and delegates to route_map.build_route_map. The image lands in the
        agent's observations dir (overwritten per tick — it is ephemeral sense
        data, though the cockpit can peek at the latest one). Returns None when
        anything is missing (no PlaceDB, unbounded grid, unknown destination,
        no current cell) — the tick proceeds without a map.
        """
        if self.place_db is None or not self.world_grid.has_bounds:
            return None
        col, row = self._cell_col_row(observation.get("grid"))
        if col is None:
            return None
        end = self._resolve_place_endpoint(agent_id, destination_name)
        if end is None:
            return None
        xyz = _loc_xyz(observation.get("location"))
        if xyz is None:
            return None
        route = route_map.build_route_map(
            self.place_db, self.world_grid, (col, row), end["cell"],
            destination_name=destination_name,
        )
        if route is None:
            return None
        # Survey districts are background knowledge, not movement waypoints.
        # Report the actual place bearing even when both positions share a cell.
        dx, dy = end["xy"][0] - xyz[0], end["xy"][1] - xyz[1]
        route["to"].update(name=destination_name,
                           bearing=yaw_to_compass(math.degrees(math.atan2(dy, dx))),
                           distance_m=round(math.hypot(dx, dy) / 100.0, 1))
        image = route_map.render_map_image(
            route, self._agents_dir / agent_id / "observations" / "route_map.png"
        )
        if image is not None:
            route["image_path"] = str(image)
        return route

    def _cell_col_row(self, grid: dict | None) -> tuple[int, int] | tuple[None, None]:
        """Extract (col, row) integers from a world_grid.locate() result dict."""
        if not grid:
            return None, None
        try:
            return int(grid["col"]), int(grid["row"])
        except (KeyError, TypeError, ValueError):
            return None, None

    # ── Explore mode ───────────────────────────────────────────────────────────

    def _spatial_map(self, agent_id: str) -> SpatialMap:
        """Load (and cache) this agent's per-agent egocentric map."""
        smap = self._spatial.get(agent_id)
        if smap is None:
            path = self._agents_dir / agent_id / "spatial_map.json"
            # Tile with the world grid's cell size so map cells and grid keys align.
            smap = SpatialMap.load(
                path, cell_size=self.world_grid.cell_size,
                origin_x=self.world_grid.origin_x, origin_y=self.world_grid.origin_y,
            )
            self._spatial[agent_id] = smap
        return smap

    def _social(self, agent_id: str) -> SocialMemory:
        """Load (and cache) this agent's acquaintance store."""
        s = self._social_mem.get(agent_id)
        if s is None:
            s = SocialMemory.load(self._agents_dir / agent_id / "social.json")
            self._social_mem[agent_id] = s
        return s

    def _record_utterance(self, agent: Agent, action: dict, observation: dict) -> None:
        """Publish one spoken line so APCs in earshot can actually hear it (#45).

        Until this existed, ``speak_to`` only produced a bubble in the engine:
        the reaction gate's "someone is speaking to you" clause could never fire
        because no agent ever received another's speech.
        """
        message = str(action.get("message") or "").strip()
        here = _loc_xyz(observation.get("location"))
        if not message or here is None:
            return
        self._utterance_seq += 1
        self._utterances.append({
            "id": self._utterance_seq,
            "speaker": getattr(agent, "display_name", agent.agent_id),
            "speaker_id": agent.agent_id,
            "text": message[:400],
            "world_time": str(observation.get("world_time") or ""),
            "x": here[0],
            "y": here[1],
        })
        del self._utterances[:-_MAX_UTTERANCES]

    def _attach_heard_speech(self, agent: Agent, observation: dict) -> None:
        """Deliver unheard speech from APCs within earshot, then mark it consumed."""
        here = _loc_xyz(observation.get("location"))
        if here is None or not self._utterances:
            return
        since = self._heard_seq.get(agent.agent_id, 0)
        heard = []
        for utterance in self._utterances:
            if utterance["id"] <= since or utterance["speaker_id"] == agent.agent_id:
                continue
            distance = math.hypot(utterance["x"] - here[0], utterance["y"] - here[1])
            if distance > _HEARING_CM:
                continue
            heard.append({"speaker": utterance["speaker"], "text": utterance["text"],
                          "world_time": utterance["world_time"],
                          "distance_cm": round(distance, 1)})
        # Out-of-earshot lines are consumed too: overhearing them one tick later
        # from across the square would be worse than missing them.
        self._heard_seq[agent.agent_id] = self._utterances[-1]["id"]
        if heard:
            observation["heard"] = heard
            logger.info("[%s] heard: %s", agent.agent_id,
                        "; ".join(f"{h['speaker']}: {h['text'][:60]}" for h in heard))

    def _identify_visible_apcs(self, agent: Agent, observation: dict) -> None:
        """Name the APCs actually in this agent's forward view (#44).

        The engine already knows who is standing where; the VLM only ever
        reports "unknown person". Resolving identity here — from position and
        yaw, deterministically — is what lets social memory, don't-re-greet, and
        the friend-interrupt stop gating on a store that is never populated.
        Proximity alone is not sighting: someone behind the agent is skipped.
        """
        here = _loc_xyz(observation.get("location"))
        yaw = _yaw_of(observation.get("rotation"))
        if here is None or yaw is None:
            return

        others = []
        for other_id, pos in self._live_pos.items():
            if other_id == agent.agent_id:
                continue
            other = self.agents.get(other_id)
            others.append({"name": getattr(other, "display_name", other_id),
                           "x": pos["x"], "y": pos["y"]})
        identified = recognition.visible_characters((here[0], here[1]), yaw, others)
        if not identified:
            return

        seen = observation.setdefault("seen", {})
        seen["characters"] = recognition.merge_identities(
            seen.get("characters") or [], identified)
        observation["recognized"] = identified
        logger.info("[%s] recognized: %s", agent.agent_id,
                    ", ".join(f"{p['name']} ({p['distance_cm']:.0f}cm {p['bearing']})"
                              for p in identified))

    def _record_sightings(self, agent_id: str, observation: dict) -> None:
        """Persist perceived named characters into this agent's social memory.

        Pulls characters out of ``observation["seen"]``, keys each sighting to
        the current grid cell + world time, and saves. Anonymous figures
        ("unknown person") are dropped by SocialMemory — only identities are
        remembered. Pure (no engine/LLM/socket), so it runs in the parallel
        perceive phase: each agent only writes its own social.json.
        """
        characters = (observation.get("seen") or {}).get("characters") or []
        if not characters:
            return
        grid = observation.get("grid") or {}
        cell_key = grid.get("key")
        world_time = observation.get("world_time", "")
        social = self._social(agent_id)
        changed = False
        for c in characters:
            if social.record_sighting(c.get("label", ""), cell_key, world_time):
                changed = True
        if changed:
            social.save(self._agents_dir / agent_id / "social.json")

    def _record_interactions(self, agent_id: str, observation: dict, sentiment_delta: float = 0.0) -> None:
        """Log a social interaction with each named person currently perceived.

        Called when the agent speaks: speech has no explicit target, so the
        interaction is attributed to whoever it can see. Sentiment defaults to
        neutral — we don't infer affinity from a message without a real signal
        (that would need an LLM call the loop avoids). Pure, per-agent file.
        """
        characters = (observation.get("seen") or {}).get("characters") or []
        world_time = observation.get("world_time", "")
        social = self._social(agent_id)
        changed = False
        for c in characters:
            if social.record_interaction(c.get("label", ""), world_time, sentiment_delta):
                changed = True
        if changed:
            social.save(self._agents_dir / agent_id / "social.json")

    def _mark_recent_greetings(self, acquaintances: list, world_time) -> list:
        """Copy each acquaintance with a ``recently_greeted`` flag (#12.1): True
        when this agent spoke with them within ``_GREET_COOLDOWN_MINUTES`` of now
        (sim-time). Copies rather than mutates so the derived flag never leaks
        into the persisted social store. A backwards clock (day restart) reads as
        not-recent, so greetings resume after a fresh day.
        """
        out = []
        for a in acquaintances:
            li = a.get("last_interacted")
            recent = False
            if li and world_time:
                elapsed = planner.minutes_between(li, world_time)
                recent = 0 <= elapsed < _GREET_COOLDOWN_MINUTES
            out.append({**a, "recently_greeted": recent})
        return out

    def _active_survey_interrupt(self, agent: Agent) -> dict | None:
        """Return the valid active survey record, if this APC owns one."""
        record = getattr(agent, "active_interrupt", None)
        if isinstance(record, dict) and record.get("kind") == "survey":
            return record
        return None

    def _has_active_survey(self, agent: Agent) -> bool:
        """Whether this APC's persisted lifecycle currently owns a survey."""
        return self._active_survey_interrupt(agent) is not None

    def _record_interrupt_event(self, agent: Agent, event: str, record: dict | None) -> None:
        """Best-effort audit feed entry for an interruption lifecycle transition."""
        writer = getattr(self.memory, "record_interrupt_event", None)
        if callable(writer) and isinstance(record, dict):
            writer(agent.agent_id, event, record)

    @staticmethod
    def _survey_progress_from_record(record: dict | None) -> dict | None:
        if not isinstance(record, dict) or record.get("kind") != "survey":
            return None
        progress = (record.get("payload") or {}).get("survey_progress")
        return copy.deepcopy(progress) if isinstance(progress, dict) else None

    def _survey_progress(self, agent: Agent) -> dict | None:
        """Return authoritative transient progress for an active survey only."""
        return self._survey_progress_from_record(self._active_survey_interrupt(agent))

    def _update_survey_progress(self, agent: Agent, **changes) -> dict | None:
        """Persist a same-interruption survey progress update."""
        active = self._active_survey_interrupt(agent)
        progress = self._survey_progress_from_record(active)
        if active is None or progress is None:
            return None
        progress.update(changes)
        updated = copy.deepcopy(active)
        updated.setdefault("payload", {})["survey_progress"] = progress
        replace = getattr(agent, "replace_active_interrupt", None)
        if not callable(replace) or not replace(updated, self._agents_dir):
            return None
        return progress

    def _finish_survey_heading(self, agent: Agent, result: dict) -> None:
        """Persist and audit one attempted deterministic heading."""
        progress = self._survey_progress(agent)
        if progress is None:
            return
        heading = str(result.get("direction") or progress.get("current_heading") or "?")
        succeeded = result.get("status") == "success"
        completed = list(progress.get("completed_headings") or [])
        failed = list(progress.get("failed_headings") or [])
        target = completed if succeeded else failed
        if heading not in target:
            target.append(heading)
        last_result = {"heading": heading,
                       "status": "success" if succeeded else "error"}
        if result.get("error"):
            last_result["error"] = str(result["error"])
        progress = self._update_survey_progress(
            agent, phase="surveying", current_heading=None,
            completed_headings=completed, failed_headings=failed,
            last_result=last_result,
        )
        writer = getattr(self.memory, "record_survey_event", None)
        if callable(writer) and progress is not None:
            payload = (agent.active_interrupt.get("payload") or {})
            writer(agent.agent_id, {
                "col": payload.get("col"), "row": payload.get("row"),
                "heading": heading, "status": last_result["status"],
                "completed_headings": completed, "failed_headings": failed,
                **({"error": last_result["error"]} if last_result.get("error") else {}),
            })

    def _record_offer_events(self, agent: Agent, record: dict, result: dict) -> None:
        """Record an offer plus its immediate activation/preemption outcome."""
        self._record_interrupt_event(agent, "offered", record)
        transition = result.get("transition")
        if transition == "activated":
            self._record_interrupt_event(agent, transition, result.get("active"))
        elif transition == "preempted":
            # The preempted event narrates the work displaced from attention;
            # recording the incoming active record here would invert that fact.
            self._record_interrupt_event(agent, "preempted", result.get("displaced"))
            self._record_interrupt_event(agent, "activated", result.get("active"))

    def _terminate_active_interrupt(self, agent: Agent, status: str, outcome: str,
                                    resolved_at: str, extra: dict | None = None) -> dict:
        """Resolve an active record and make the terminal state auditable.

        ``extra`` rides on the decision-log event only (#101: the path answer
        behind an abandoned survey travel); the persisted record is unchanged.
        """
        result = agent.terminate_interrupt(status, outcome, self._agents_dir, resolved_at)
        logged = result.get("last_interrupt")
        if extra and isinstance(logged, dict):
            logged = {**logged, **extra}
        self._record_interrupt_event(agent, status, logged)
        if result.get("active") is not None:
            self._record_interrupt_event(agent, "activated", result.get("active"))
            self._pause_for_open_chat(agent)
        return result

    def _apply_cell_verdict(self, agent: Agent, action: dict,
                            observation: dict) -> dict | None:
        """Store the APC's own ruling on a cell: refuse it, or take it back (#59).

        The map had two states, named and unexplored, so a cell an APC looked at
        and rejected relaxed straight back to "unsurveyed ground" — a permanent
        lure that pulled Dufus into the same corn field across four runs. This
        is the third state, and the APC writes it, not us: nothing here stops
        him walking into a refused cell if he changes his mind. What it changes
        is what the map advertises.

        Resolves against the grid, never the engine. Returns the action to run
        instead (idle), or None when this was not a verdict.
        """
        kind = action.get("type")
        if kind not in ("refuse_cell", "allow_cell") or not self.place_db:
            return None
        agent_id = agent.agent_id
        direction = str(action.get("direction") or "").strip()
        target = None
        if direction:
            target = self._direction_target(observation, direction)
            grid = self.world_grid.locate(target[0], target[1]) if target else None
            if grid is None:
                logger.warning("[%s] %s: cannot resolve direction %r — ignoring",
                               agent_id, kind, direction)
                return {"type": "idle", "_note": f"could not resolve direction {direction!r}"}
        else:
            grid = observation.get("grid")

        # scope "spot": rule on the ~9 m patch one step that way, not the whole
        # 30 m cell (#78) — a bad backyard must not un-target a surveyable cell.
        if str(action.get("scope") or "").strip().lower() == "spot":
            xyz = _loc_xyz(observation.get("location"))
            placed = direction or "here"
            if target is None and kind == "refuse_cell":
                # A refusal with no direction used to fall back to the APC's own
                # position, dropping a 450 cm circle on the ground it was
                # standing on — a trap it wrote itself, and every step out of it
                # then capped to zero. SR51 row 14 of world_places.db is the live
                # example. With no direction the only ground the mind can mean is
                # the ground it FACES, so slide the centre out exactly the way a
                # measured seal already does (#91): 2 x radius, which clears the
                # body and keeps the mark inside one heading.
                facing = _yaw_of(observation.get("rotation"))
                if xyz is None or facing is None:
                    logger.warning("[%s] %s: no position or facing — refusing to mark "
                                   "ground the body may be standing on", agent_id, kind)
                    return {"type": "idle",
                            "_note": "could not tell which ground that is — nothing marked"}
                target = list(dead_end.wall_point(
                    xyz[0], xyz[1], facing, 0.0, PLACE_EXTENT_CM / 2))
                placed = "ahead"
            elif target is None:
                # Withdrawing a patch is the opposite case: "here" really does
                # mean underfoot, and that is how an APC takes back a seal it is
                # standing in.
                target = [xyz[0], xyz[1]] if xyz else None
            if target is None:
                return {"type": "idle", "_note": "no position to rule on"}
            where = f"({target[0]:.0f}, {target[1]:.0f})"
            if kind == "refuse_cell":
                reason = str(action.get("reason") or "").strip()
                self.place_db.refuse_patch(agent_id, target[0], target[1], reason,
                                           str(observation.get("world_time") or ""))
                logger.info("[%s] refused a %s-m patch %s %s — %s", agent_id,
                            round(PLACE_EXTENT_CM / 100), placed, where, reason)
                self._pie_activity(
                    agent_id, f"refused ground {placed}: {reason}")
                return {"type": "idle",
                        "_note": f"refused the ground {placed} ({reason}) "
                                 "— the rest of the cell stays surveyable"}
            cleared = self.place_db.clear_patches_at(agent_id, target[0], target[1])
            logger.info("[%s] %s no-go patch at %s", agent_id,
                        "withdrew" if cleared else "had no", where)
            return {"type": "idle",
                    "_note": f"ground {direction or 'here'} is ordinary again"}

        col, row = self._cell_col_row(grid)
        if col is None:
            return {"type": "idle", "_note": "no grid cell to rule on"}

        if kind == "refuse_cell":
            reason = str(action.get("reason") or "").strip()
            self.place_db.refuse_cell(agent_id, col, row, reason,
                                      str(observation.get("world_time") or ""))
            logger.info("[%s] refused cell %d,%d — %s", agent_id, col, row, reason)
            self._pie_activity(agent_id, f"refused cell {col},{row}: {reason}")
            return {"type": "idle", "_note": f"refused cell {col},{row}: {reason}"}

        withdrawn = self.place_db.clear_refusal(agent_id, col, row)
        logger.info("[%s] %s refusal of cell %d,%d", agent_id,
                    "withdrew" if withdrawn else "had no", col, row)
        return {"type": "idle", "_note": f"cell {col},{row} is ordinary ground again"}

    def _resolve_survey_here(self, agent: Agent, action: dict,
                             observation: dict) -> tuple[dict, dict | None]:
        """Turn the model's `survey_here` into a real survey, on any tick path.

        Surveying is the LLM's call (#57). This used to fire the moment code
        noticed an unsurveyed cell, discarding whatever the model had decided —
        a third of SR35's ticks ran with the model's own action thrown away, and
        code, not the model, picked which ground got mapped. Now the model sees
        the cell's survey verdict as a fact and reaches for `survey_here` when
        it wants one. What it cannot do is claim a survey happened without one:
        the four headings, their order, and the capture stay deterministic,
        because which compass point to shoot next is execution, not a decision.

        Shared by the wake path and the normal tick because SR39 proved one
        handler was not enough: Dufus opened the run by asking to survey Four
        Ways Crossing, wake sent the verb straight to the bridge, and the bridge
        answered "Unknown action: survey_here". The first decision of the run
        was correct and we threw it away.

        Returns ``(action, pending)`` — ``pending`` is set only when a survey was
        newly activated and the caller must yield the tick to it.
        """
        if action.get("type") != "survey_here":
            return action, None
        if not self._should_sweep_here(observation, agent.agent_id):
            logger.info(f"[{agent.agent_id}] survey_here declined — this cell's survey is current")
            return {"type": "idle", "_note": "this cell already has a current survey"}, None
        sweep_action = self._offer_survey_interrupt(agent, observation)
        if sweep_action and sweep_action.get("_survey_pending"):
            return action, sweep_action
        return (sweep_action if sweep_action is not None else {"type": "idle"}), None

    def _offer_survey_interrupt(self, agent: Agent, observation: dict,
                                target: tuple[int, int] | None = None,
                                source: str = "agent",
                                reason: str | None = None) -> dict | None:
        """Offer a cell as a persisted survey interruption.

        Default: the cell the APC stands in, asked for by the model
        (``survey_here``). The survey mission (#96) passes ``target`` — any
        cell, however far — with ``source="mission"``: the sweep machinery
        already walks to a target cell it is not standing in, so the mission's
        whole commute rides on the existing travel/wedge handling for free.
        """
        col, row = target if target is not None else self._cell_col_row(observation.get("grid"))
        if col is None:
            return None
        for record in [getattr(agent, "active_interrupt", None),
                       *(getattr(agent, "interrupt_queue", None) or [])]:
            if (isinstance(record, dict) and record.get("kind") == "survey"
                    and (record.get("payload") or {}).get("col") == col
                    and (record.get("payload") or {}).get("row") == row):
                return self._dispatch_active_survey(agent, observation)

        route = self._routes.get(agent.agent_id) or {}
        schedule_resume = dict(observation.get("schedule") or {})
        schedule_resume.pop("agenda", None)
        record = interruptions.make_record(
            interrupt_id=f"survey:{col},{row}",
            kind="survey",
            # The APC asked for this (or the mission scheduled it — the source
            # says which). It used to say source="world" / "needs a community
            # survey", which was true when code seized the tick and became a
            # lie the moment surveying became the model's own action (#57) —
            # SR39's log read as if the world had ordered three surveys Dufus
            # in fact chose himself.
            source=source,
            reason=reason or f"{agent.agent_id} asked to survey grid cell ({col},{row})",
            requested_at=str(observation.get("world_time") or self.world_clock.now_text()),
            payload={
                "col": col, "row": row,
                "survey_progress": {
                    "phase": "pending", "current_heading": None,
                    "completed_headings": [], "failed_headings": [],
                },
            },
            resume_context={
                "current_goal": str(getattr(agent, "current_goal", "idle")),
                "schedule": schedule_resume,
                "agenda": copy.deepcopy((observation.get("agenda") or {}).get("right_now")),
                "route_destination": route.get("destination"),
            },
            preemptible=True,
            priority=interruptions.default_priority("survey"),
        )
        result = agent.offer_interrupt(
            record, self._agents_dir,
            activated_at=str(observation.get("world_time") or self.world_clock.now_text()),
        )
        self._record_offer_events(agent, record, result)
        if (result.get("transition") in {"activated", "preempted"}
                and self._active_survey_interrupt(agent) is not None):
            return {"_survey_pending": True, "interrupt_id": record["interrupt_id"]}
        return self._dispatch_active_survey(agent, observation)

    def _dispatch_active_survey(self, agent: Agent, observation: dict) -> dict | None:
        """Prepare the next active survey step, recovering it from its payload."""
        record = self._active_survey_interrupt(agent)
        if record is None:
            return None
        payload = record.get("payload") or {}
        try:
            col, row = int(payload["col"]), int(payload["row"])
        except (KeyError, TypeError, ValueError):
            self._update_survey_progress(agent, phase="failed", current_heading=None)
            self._terminate_active_interrupt(
                agent,
                "failed", "survey payload has no valid grid target",
                str(observation.get("world_time") or self.world_clock.now_text()),
            )
            return None

        if self._survey_visual_is_current(agent.agent_id, col, row):
            self._update_survey_progress(agent, phase="complete", current_heading=None)
            self._terminate_active_interrupt(
                agent,
                "resolved", "survey target is already visually complete",
                str(observation.get("world_time") or self.world_clock.now_text()),
            )
            self._cell_sweeps.pop(agent.agent_id, None)
            return None

        local = self._cell_sweeps.get(agent.agent_id)
        if local and (local.get("col"), local.get("row")) != (col, row):
            # Local execution state is disposable; persisted payload is authority.
            self._cell_sweeps.pop(agent.agent_id, None)
        action = self._sweep_step(agent.agent_id, observation, start=True, target=(col, row))
        if action is not None:
            if action.get("type") == "observe_heading":
                self._update_survey_progress(
                    agent, phase="capturing",
                    current_heading=yaw_to_compass(float(action.get("yaw", 0.0))),
                )
            elif action.get("type") == "walk_to":
                self._update_survey_progress(
                    agent, phase="moving_to_center", current_heading=None,
                )
            action["_survey_interrupt_id"] = record["interrupt_id"]
            return action

        complete = self._survey_visual_is_current(agent.agent_id, col, row)
        self._update_survey_progress(
            agent, phase="complete" if complete else "incomplete", current_heading=None,
        )
        abandon = self._survey_abandons.pop(agent.agent_id, None)
        extra = None
        outcome = "survey completed" if complete else "survey capture incomplete"
        if not complete and abandon is not None:
            outcome = abandon["outcome"]
            extra = {"path": abandon["path"], "path_end_gap_cm": abandon["path_end_gap_cm"]}
        self._terminate_active_interrupt(
            agent,
            "resolved" if complete else "failed",
            outcome,
            str(observation.get("world_time") or self.world_clock.now_text()),
            extra=extra,
        )
        self._cell_sweeps.pop(agent.agent_id, None)
        return None

    def _choose_stand_point(self, agent_id: str, agent, col: int, row: int,
                            xyz: tuple[float, float, float],
                            facing: float | None) -> tuple[str, tuple[float, float] | None]:
        """Probe the cell for the best open survey stand point (#103).

        A survey used to walk to the literal geometric centre of the cell and
        shoot its four frames from wherever that landed — SR-noted: sometimes
        against the back of a house. This probes a handful of candidate spots
        with ``radar(location=...)`` (the #101 ground+path measurement, not a
        guess) and picks the one with the most breathing room, per
        ``stand_point.score``/``choose``.

        Returns one of:
          - ``("ok", xy)`` — a real choice was measured; the caller walks the
            sweep to ``xy`` instead of the centre and persists it later.
          - ``("here", xy)`` — the body's own spot won (stay rule); nothing to
            walk, the caller keeps the explorer's forgiving arrival.
          - ``("fallback", center_xy)`` — an old plugin never measured ground
            at all (the search stopped on the first ``UNMEASURED`` probe, one
            WARNING already logged); the caller proceeds exactly as before
            #103, walking to the geometric centre, storing no stand point.
          - ``("abandon", None)`` — nothing in the cell passed both hard
            requirements; the cell is already marked blocked and the
            abandonment logged (via ``_abandon_survey_travel``) before this
            returns, so the caller only needs to stop.
        """
        center = self.world_grid.cell_center(col, row)
        if center is None:
            return "abandon", None
        if agent is None or not agent.has_unreal_binding or facing is None:
            # Nothing to probe with (no bound body, or facing unknown) —
            # behave exactly as the sweep did before #103 existed.
            return "fallback", center

        here_col, here_row = self._cell_col_row(self.world_grid.locate(xyz[0], xyz[1]))
        here_xy = (xyz[0], xyz[1]) if (here_col, here_row) == (col, row) else None

        all_candidates = stand_point.candidates(center, self.world_grid.cell_size, here_xy=here_xy)
        ring1 = [c for c in all_candidates if not c[2].startswith("ring2")]
        ring2 = [c for c in all_candidates if c[2].startswith("ring2")]

        probes = 0
        center_probe: dict | None = None
        t0 = time.perf_counter()

        def probe_ring(ring):
            nonlocal probes, center_probe
            scored = []
            for x, y, label in ring:
                result = self.bridge.radar(
                    agent.bound_unreal_actor_name, distance_cm=_RADAR_RANGE_CM,
                    yaw_offset_deg=-facing, location=(x, y, xyz[2]),
                ) or {}
                probes += 1
                if label == "center":
                    center_probe = result
                probe = dict(result)
                probe["dist_to_center_cm"] = math.hypot(x - center[0], y - center[1])
                s = stand_point.score(probe)
                if s == stand_point.UNMEASURED:
                    return None
                scored.append((label, (x, y), s))
            return scored

        scored = probe_ring(ring1)
        if scored is None:
            logger.warning(
                f"[{agent_id}] sweep: stand point not measured — plugin has no "
                "ground sense; using the cell centre"
            )
            return "fallback", center

        chosen = stand_point.choose(scored)
        if chosen is None:
            scored = probe_ring(ring2)
            if scored is None:
                logger.warning(
                    f"[{agent_id}] sweep: stand point not measured — plugin has no "
                    "ground sense; using the cell centre"
                )
                return "fallback", center
            chosen = stand_point.choose(scored)

        elapsed_ms = (time.perf_counter() - t0) * 1000.0
        budget = f"{probes} probes, {elapsed_ms:.0f} ms"

        if chosen is None:
            self._abandon_survey_travel(
                agent_id, {"col": col, "row": row},
                f"no open ground in the cell ({budget})",
            )
            return "abandon", None

        label, xy, sc = chosen
        min_air_m = sc[0] / 100.0
        if label == "center":
            logger.info(f"[{agent_id}] sweep: ({col},{row}) stand point is the "
                        f"centre — {budget}")
        elif label == "here":
            best = max((t for t in scored if t[2] is not None), key=lambda t: t[2])
            logger.info(
                f"[{agent_id}] sweep: ({col},{row}) stand point staying here "
                f"(min air {min_air_m:.1f} m vs best {best[2][0] / 100.0:.1f} m) — {budget}"
            )
        else:
            dx, dy = xy[0] - center[0], xy[1] - center[1]
            winner_dir = yaw_to_compass(math.degrees(math.atan2(dy, dx)) % 360.0)
            dist_m = math.hypot(dx, dy) / 100.0
            center_ring = (center_probe or {}).get("ring") or []
            if center_ring:
                tight = min(center_ring, key=lambda s: s.get("clearance_cm", 0.0))
                center_dir = yaw_to_compass(float(tight.get("world_yaw", 0.0)))
                center_min_m = float(tight.get("clearance_cm", 0.0)) / 100.0
                center_clause = f"centre had {center_min_m:.1f} m of air to the {center_dir} "
            else:
                center_clause = ""
            logger.info(
                f"[{agent_id}] sweep: ({col},{row}) stand point {dist_m:.1f} m {winner_dir} "
                f"of centre — {center_clause}(min air here {min_air_m:.1f} m) — {budget}"
            )
        return ("here" if label == "here" else "ok"), xy

    def _sweep_step(self, agent_id: str, observation: dict, start: bool = True,
                    target: tuple[int, int] | None = None) -> dict | None:
        """One step of the shared sweep capability (#11.1).

        Any APC that needs an unexplored cell walks to the cell center, observes
        each compass heading, then drops the community breadcrumb
        (``PlaceDB.mark_swept``) so every other APC skips the costly 360.

        With ``start=True`` a new sweep may begin when the current cell is
        genuinely unexplored; with ``start=False`` only an already-active sweep
        continues. Returns the next sweep sub-action, or None when there is
        nothing to do (nothing active/startable, missing PlaceDB / bounds /
        grid, or the sweep just finished). The returned action carries
        ``_sweep_interrupt`` so callers can see the tick was spent sweeping.
        """
        col, row = target if target is not None else self._cell_col_row(observation.get("grid"))
        if col is None:
            return None
        xyz = _loc_xyz(observation.get("location"))
        if xyz is None:
            return None

        active = self._cell_sweeps.get(agent_id)
        if active is None:
            if not start:
                return None
            # A name/breadcrumb is not visual memory; only a complete place
            # image makes this community cell survey-ready.
            if self.place_db is None or self._survey_visual_is_current(agent_id, col, row):
                return None
            # "Don't go in there" is durable: a cell already found unreachable is
            # never re-surveyed, or the abandoned walk restarts on the next tick.
            center = self.world_grid.cell_center(col, row)
            if center is not None and self._spatial_map(agent_id).is_blocked(
                    self.world_grid.locate(center[0], center[1])["key"]):
                return None
            progress = self._survey_progress(
                self.agents.get(agent_id)
            ) if self.agents.get(agent_id) is not None else None
            attempted = set((progress or {}).get("completed_headings") or [])
            attempted.update((progress or {}).get("failed_headings") or [])
            remaining = [
                yaw for yaw in cell_sweep.compass_headings()
                if yaw_to_compass(yaw) not in attempted
            ]
            # A survey-priority APC is an explorer: it surveys the cell it is
            # crossing, from wherever inside that cell it happens to be standing,
            # so the goto_center leg never emits and the APC never doubles back
            # to map a cell it has already walked through. Containment is
            # enforced separately below — this tolerance only decides whether an
            # APC *already inside* the target cell still walks to its center.
            explorer = bool(getattr(self.agents.get(agent_id), "survey_priority", False))
            sweep = cell_sweep.default_sweep(
                self.world_grid, col, row, z=xyz[2], headings=remaining,
                arrive_tolerance=self.world_grid.cell_size if explorer else None,
            )
            if sweep is None:
                return None
            # #103: the geometric centre `default_sweep` just aimed at is not
            # always open ground — probe the cell for the best spot and walk
            # the sweep there instead. An abandonment (nothing passed) is
            # fully handled inside the helper; a fallback (old plugin) leaves
            # `sweep` untouched, walking to the centre exactly as before.
            mode, stand_xy = self._choose_stand_point(
                agent_id, self.agents.get(agent_id), col, row, xyz,
                _yaw_of(observation.get("rotation")),
            )
            if mode == "abandon":
                return None
            # The survey turns the avatar through all four cardinals, so the
            # facing it arrived with must be remembered now or it is gone (#56).
            active = {"sweep": sweep, "col": col, "row": row, "views": [],
                      "entry_yaw": _yaw_of(observation.get("rotation"))}
            if mode in ("ok", "here"):
                active["stand_point"] = stand_xy
                active["travel_target"] = stand_xy
            if mode == "ok":
                # A measured point elsewhere in the cell is only worth anything
                # if the body actually goes there. The explorer tolerance above
                # (a whole cell) would let the sweep shoot from wherever the
                # body entered the cell — SR-noted: the back of a house.
                sweep = cell_sweep.CellSweep(
                    center=stand_xy, z=xyz[2], headings=remaining,
                    arrive_tolerance=_STAND_POINT_ARRIVE_CM,
                )
                active["sweep"] = sweep
            self._cell_sweeps[agent_id] = active
            logger.info(f"[{agent_id}] sweep: unexplored cell ({col},{row}) — sweeping")

        # A survey may only photograph the cell the APC is standing in. SR33
        # captured (5,5) and (5,6) from one spot — 15.7 m *outside* (5,5) — and
        # wrote two community place images from the same four frames, because
        # arrival was a distance test and a persisted survey interrupt keeps its
        # target across ticks and runs. Containment is the authority: outside the
        # target cell, the only legal sweep step is walking to its center.
        here_col, here_row = self._cell_col_row(observation.get("grid"))
        if (here_col, here_row) != (active["col"], active["row"]):
            center = self.world_grid.cell_center(active["col"], active["row"])
            if center is None:
                return None
            if self._survey_travel_is_wedged(agent_id, active, (xyz[0], xyz[1])):
                return None
            # #101: a partial path proven to end inside the target cell is
            # aimed at directly — the engine already measured that the literal
            # centre is not what is reachable.
            target_xy = active.get("travel_target") or center
            aim = "the path-tested point" if active.get("travel_target") else "that cell's center"
            logger.info(
                f"[{agent_id}] sweep: standing in ({here_col},{here_row}) but surveying "
                f"({active['col']},{active['row']}) — walking to {aim} "
                f"(travel tick {active['travel_ticks']}/{_MAX_SURVEY_TRAVEL_TICKS})"
            )
            return {"type": "walk_to", "location": [target_xy[0], target_xy[1], xyz[2]],
                    "_sweep": "goto_center", "_sweep_interrupt": True}
        active["travel_ticks"] = 0

        action = active["sweep"].next_action((xyz[0], xyz[1]))
        if action.get("type") == "sweep_done":
            self._restore_facing_after_survey(agent_id, active, observation)
            image = self._save_place_visual(
                agent_id, active["col"], active["row"], active.get("views", [])
            )
            if image:
                self.place_db.mark_swept(
                    agent_id, active["col"], active["row"],
                    observation.get("world_time", self.world_clock.now_text())
                )
                # #103: persisted alongside the breadcrumb, on completion only —
                # an abandoned or incomplete sweep never measured a "final"
                # stand point worth recording.
                stand = active.get("stand_point")
                if stand is not None:
                    self.place_db.set_stand_point(
                        active["col"], active["row"], stand[0], stand[1])
            self._cell_sweeps.pop(agent_id, None)
            # A finished survey is a decision point: without this the view is
            # unchanged, the scene gate idles the APC, and the run reads as
            # "things sort of stopped" (SR44 ticks 29-31). One full think, now.
            self._force_next_decide.add(agent_id)
            logger.info(
                f"[{agent_id}] sweep: ({active['col']},{active['row']}) "
                + ("visual saved; breadcrumb dropped" if image
                   else "visual incomplete; cell remains due for survey")
            )
            return None
        action["_sweep_interrupt"] = True
        return action

    def _restore_facing_after_survey(self, agent_id: str, active: dict,
                                     observation: dict) -> None:
        """Turn the avatar back to the facing it arrived with (#56).

        A survey turns through E/S/W/N and the last heading is N, so without
        this the avatar is left permanently facing north — and every
        facing-relative word the LLM then uses is measured from north.
        SR34 proved it: the survey of (6,6) ended at yaw -90, the LLM said
        "turn back the way I came", and ``back`` resolved to south — straight
        back into the corn field it was trying to leave. The wake sweep has
        always restored its facing (see ``_wake_sweep``); the cell survey never
        did. A failed turn is logged, never fatal — the survey itself is done.
        """
        agent = self.agents.get(agent_id)
        entry_yaw = active.get("entry_yaw")
        if agent is None or entry_yaw is None or not agent.has_unreal_binding:
            return
        result = self.bridge.set_facing(
            agent.bound_unreal_actor_name, observation.get("location"), entry_yaw)
        if result.get("error"):
            logger.warning(f"[{agent_id}] sweep: could not restore facing "
                           f"{entry_yaw:.0f} after survey: {result['error']}")
        else:
            logger.info(f"[{agent_id}] sweep: facing restored to "
                        f"{yaw_to_compass(entry_yaw)} ({entry_yaw:.0f})")

    def _abandon_survey_travel(self, agent_id: str, active: dict, reason: str,
                               path: str | None = None,
                               path_end_gap_cm: float | None = None) -> None:
        """Mark the target cell unreachable and drop the local sweep state (#91/#101).

        Shared by the distance-based backstop and the #101 path-answer check
        below — both reach the same conclusion by different evidence, and both
        need the same cleanup. The reason and the path answer are stashed so
        the ``interrupt_failed`` decision-log event carries them (SR57 showed
        only the runner log did).
        """
        self._survey_abandons[agent_id] = {
            "outcome": f"survey abandoned — {reason}",
            "path": path,
            "path_end_gap_cm": path_end_gap_cm,
        }
        center = self.world_grid.cell_center(active["col"], active["row"])
        if center is not None:
            self._spatial_map(agent_id).mark_blocked(
                self.world_grid.locate(center[0], center[1])["key"]
            )
        logger.warning(
            f"[{agent_id}] sweep: cell ({active['col']},{active['row']}) abandoned — "
            f"{reason}; marking it unreachable"
        )
        self._cell_sweeps.pop(agent_id, None)

    def _survey_travel_is_wedged(self, agent_id: str, active: dict,
                                 xy: tuple[float, float]) -> bool:
        """Give up on a survey whose target cell cannot actually be walked into.

        Containment means an unreachable cell is now a walk the APC would repeat
        forever — the bridge accepts a move order that the navigation never
        completes, so "success" proves nothing. Progress is measured in metres
        moved, not in orders accepted. On the last allowed tick the cell is
        marked blocked in the APC's own map so exploration stops choosing it,
        and the caller resolves the interruption as an incomplete survey.

        #101 (SR56): before falling back to that 4-tick, metres-moved backstop,
        this reads the PATH ANSWER the previous goto-center order already got
        back on tick 1 — ``_note_survey_travel_result`` stashed it onto this
        same ``active`` dict right after the order was executed. ``none`` or a
        ``partial`` path ending outside the target cell abandon immediately,
        the way SR56's 100 s of dead ticks on the (5,8) slab never had to
        happen. A ``partial`` path ending INSIDE the cell is not a failure —
        the engine has already proven that point reachable, so the next walk
        order aims at it instead of the literal centre. A ``full`` path (or no
        plugin new enough to answer at all) leaves the old backstop in place
        exactly as before.
        """
        path = active.pop("last_path", None)
        path_end = active.pop("last_path_end", None)
        path_end_gap_cm = active.pop("last_path_end_gap_cm", None)
        if path in ("none", "partial"):
            end_col, end_row = (None, None)
            if isinstance(path_end, dict):
                end_col, end_row = self._cell_col_row(
                    self.world_grid.locate(path_end.get("x", 0.0), path_end.get("y", 0.0)))
            inside_target = (end_col, end_row) == (active["col"], active["row"])
            if path == "partial" and inside_target:
                active["travel_target"] = [path_end["x"], path_end["y"]]
                active["travel_ticks"] = 0
                return False
            reason = ("no path to the cell centre" if path == "none"
                      else "the reachable path ends outside the target cell")
            self._abandon_survey_travel(agent_id, active, f"{reason} (measured on tick 1)",
                                        path=path, path_end_gap_cm=path_end_gap_cm)
            return True

        previous = active.get("travel_from")
        moved = (math.hypot(xy[0] - previous[0], xy[1] - previous[1])
                 if previous is not None else None)
        active["travel_from"] = xy
        if moved is not None and moved >= _SURVEY_TRAVEL_PROGRESS_CM:
            active["travel_ticks"] = 0        # real progress — keep walking
            return False

        active["travel_ticks"] = active.get("travel_ticks", 0) + 1
        if active["travel_ticks"] <= _MAX_SURVEY_TRAVEL_TICKS:
            return False

        self._abandon_survey_travel(
            agent_id, active,
            f"{_MAX_SURVEY_TRAVEL_TICKS} travel ticks moved less than "
            f"{_SURVEY_TRAVEL_PROGRESS_CM:.0f}cm")
        return True

    def _note_survey_travel_result(self, agent_id: str, action: dict, result: dict) -> None:
        """Stash a goto-center move's path answer for next tick's wedge check (#101).

        ``_execute_world_action`` runs the walk order this tick and gets the
        path answer back immediately; the sweep only re-examines its travel on
        the NEXT tick's ``_sweep_step`` call, so the answer has to ride on the
        active sweep's own dict to survive until then.
        """
        if action.get("_sweep") != "goto_center":
            return
        active = self._cell_sweeps.get(agent_id)
        if active is None or "path" not in result:
            return
        active["last_path"] = result.get("path")
        active["last_path_end"] = result.get("path_end")
        active["last_path_end_gap_cm"] = result.get("path_end_gap_cm")

    def _cell_survey_fact(self, agent: Agent, observation: dict) -> dict | None:
        """Authoritative survey verdict for the cell the APC is standing in (#40).

        The survey *progress* fact only exists while an interruption is active,
        so between surveys cognition had no deterministic answer to "does here
        still need surveying?" — which is how SR28 produced narration about
        missing headings for a cell that had just been resolved.
        """
        col, row = self._cell_col_row(observation.get("grid"))
        if col is None or self.place_db is None:
            return None
        payload = (self._active_survey_interrupt(agent) or {}).get("payload") or {}
        progress = self._survey_progress(agent) or {}
        active_here = bool(progress and payload.get("col") == col
                           and payload.get("row") == row)
        fresh = self._survey_visual_is_current(agent.agent_id, col, row)
        return {
            "cell": f"{col},{row}",
            "col": col,
            "row": row,
            "fresh": fresh,
            "needs_survey": not fresh,
            "active_here": active_here,
            "completed_headings": ([str(x) for x in progress.get("completed_headings") or []]
                                   if active_here else []),
            "failed_headings": ([str(x) for x in progress.get("failed_headings") or []]
                                if active_here else []),
            "total_headings": len(cell_sweep.compass_headings()),
        }

    def _ground_survey_narration(self, agent: Agent, decision: dict, action: dict,
                                 result: dict, observation: dict) -> list[str]:
        """Drop model claims about surveying that no deterministic fact supports (#40).

        Prompt grounding alone was not enough in SR28. A capture is only real
        when this tick actually ran a survey heading, and a cell only needs
        surveying when the database says so — both are known here, so the claim
        is checked in code rather than trusted from the model.
        """
        captured = bool(action.get("_survey_interrupt_id")
                        and action.get("type") == "observe_heading"
                        and (result.get("status") == "success" or result.get("success")))
        facts = observation.get("cell_survey")
        needs_survey = bool(facts.get("needs_survey")) if isinstance(facts, dict) else True

        dropped: list[str] = []
        for field in ("thought_summary", "memory_update"):
            text = decision.get(field)
            if not isinstance(text, str) or not text.strip():
                continue
            kept, reasons = filter_survey_claims(
                text, captured=captured, needs_survey=needs_survey)
            if not reasons:
                continue
            dropped.extend(reasons)
            decision[field] = kept or (
                "Nothing about surveying this cell can be stated from what actually happened."
                if field == "thought_summary" else None)

        if dropped:
            # Fail loud: an invented capture is exactly the class of bug that
            # made SR28's logs untrustworthy, so it is reported, not smoothed over.
            logger.warning("[%s] dropped unsupported survey narration: %s",
                           agent.agent_id, "; ".join(sorted(set(dropped))))
            observation["_survey_narration_dropped"] = sorted(set(dropped))
        return dropped

    def _should_sweep_here(self, observation: dict, agent_id: str = "") -> bool:
        """True when the current grid cell still needs a community place image.

        This is the schedule-agnostic spatial/storage gate. The act-phase caller
        applies #34's routine policy plus the per-APC survey-priority override.
        Needs a bounded grid (a cell center to walk to) and a PlaceDB (somewhere
        to drop the breadcrumb). Always False in Play mode (#102): no new cells
        get swept, however the cell would otherwise score.
        """
        if self.mode != "survey":
            return False
        col, row = self._cell_col_row(observation.get("grid"))
        if col is None or self.place_db is None:
            return False
        return not self._survey_visual_is_current(agent_id, col, row)

    def _survey_visual_is_current(self, agent_id: str, col: int, row: int) -> bool:
        """True when a community composite exists (staleness OFF per user).

        SR44 (2026-08-19): the 24 h staleness window marked every July survey
        as "needs a survey", so Dufus re-shot covered ground instead of pushing
        outward. The user turned refresh off: surveyed is surveyed, forever,
        until an explicit re-survey feature (#39/#35) is deliberately invoked.
        The /map still *labels* old surveys stale — display only.
        """
        if self.place_db is None:
            return False
        if self.place_db.current_place_image(agent_id, col, row) is None:
            return False
        if not SURVEY_STALE_REFRESH:
            return True
        return not self.place_db.is_stale(col, row, COMMUNITY_SURVEY_MAX_AGE_SECONDS)

    def _episodic(self, agent_id: str) -> EpisodicLog:
        """Load (and cache) this agent's append-only episodic event log."""
        log = self._episodic_log.get(agent_id)
        if log is None:
            log = EpisodicLog(self._agents_dir / agent_id / "episodes.jsonl")
            self._episodic_log[agent_id] = log
        return log

    def _record_episode(self, agent_id: str, observation: dict, action: dict, result: dict) -> None:
        """Append a structured "what happened" event for this acted tick.

        Captures where (grid cell + place), who was seen (named only), what the
        agent did, and the outcome — so overnight runs keep a queryable history
        beyond the 30-item memory.json window.
        """
        grid = observation.get("grid") or {}
        place_list = observation.get("place") or []
        characters = (observation.get("seen") or {}).get("characters") or []
        saw = [c.get("label") for c in characters
               if c.get("label") and not is_anonymous(c.get("label", ""))]
        self._episodic(agent_id).record({
            "world_time": observation.get("world_time", ""),
            "grid_cell": _cell_label(grid),
            "place": place_list[0] if place_list else None,
            "place_image_id": observation.get("place_image_id"),
            "saw": saw,
            "action": action.get("type"),
            "outcome": result.get("status") or result.get("success"),
        })

    def _grid_and_place(self, agent_id: str, location) -> tuple[dict | None, list[str]]:
        """Fixed world-grid cell for a location + known place labels for it.

        Pure lookups (grid math + this agent's saved spatial map) — no engine
        or LLM calls, so it runs every tick even when perception is skipped.
        """
        xyz = _loc_xyz(location)
        if xyz is None:
            return None, []
        grid = self.world_grid.locate(xyz[0], xyz[1])
        place = self._spatial_map(agent_id).place_labels(grid["key"])
        return grid, place

    def _note_eyes(self, agent_id: str, location, yaw, seen: dict | None) -> None:
        """File what this APC's own eyes reported down one heading (#77).

        Every perceived view with a known facing — the tick view, a wake sweep
        heading, a survey sweep heading — carries ``ground_ahead``/``path_ahead``:
        what the walkable path in the frame is made of, and whether it stays
        open. Cached per compass word for the spot the APC stands on, and
        dropped the moment it moves (same one-spot scope as `_record_attempt`):
        look-before-step means the looks taken *here* inform the step taken
        *from here*.
        """
        if not isinstance(seen, dict) or seen.get("error"):
            return
        ahead = str(seen.get("ground_ahead") or "").strip()
        path = str(seen.get("path_ahead") or "").strip()
        if not ahead and not path:
            return
        xyz = _loc_xyz(location)
        if xyz is None or yaw is None:
            return
        word = _COMPASS_LETTER_WORD.get(yaw_to_compass(float(yaw)))
        if not word:
            return
        record = self._eyes.get(agent_id)
        if (record is None
                or math.hypot(xyz[0] - record["at"][0],
                              xyz[1] - record["at"][1]) > _EYES_VALID_CM):
            record = {"at": (xyz[0], xyz[1]), "views": {}}
            self._eyes[agent_id] = record
        record["views"][word] = {"ground_ahead": ahead, "path_ahead": path}

    def _direction_places(self, agent_id: str, location, rotation=None) -> dict[str, dict]:
        """Lizard-brain navigation sense: the grid cell one step (~15m) ahead in
        each walkable direction, plus what the SHARED world map knows about it.

        Reads PlaceDB (shared by every avatar), so one agent's discoveries steer
        another's — Maren's named cells show up in Dufus's options. Each value is
        ``{"cell": "col,row", "place": <name or None>, "ground": [...],
        "refusals": [...]}``; ``place is None`` means the cell is still
        unexplored, a good place to go map next, and ``ground`` is what APCs
        have actually stood on there.

        The ground is the point of this fact when an APC is stuck (#58). A name
        says a cell was *seen*; footing says it was *walked* — so a way out
        already proven by somebody's feet stops being something the model has to
        guess at from the picture. An empty list means nobody has stood there.

        Keyed by compass, not by forward/left/right (#59). We tell the APC that
        compass words are the vocabulary and body-relative words silently change
        meaning — then handed it a next-cell map keyed by exactly those
        body-relative words, which is the only map it had. SR39 answered in the
        vocabulary we gave it: 13 of 15 walks were forward/right/back. Rotation
        is no longer needed to build this at all, which is the point.
        """
        xyz = _loc_xyz(location)
        if xyz is None:
            return {}
        eyes = self._eyes.get(agent_id)
        if eyes is not None and math.hypot(xyz[0] - eyes["at"][0],
                                           xyz[1] - eyes["at"][1]) > _EYES_VALID_CM:
            eyes = None  # looks taken somewhere else say nothing about here (#77)
        # One fetch for all eight headings — the line scan below tests every
        # patch against every sample point, and eight DB round-trips to answer
        # the same question is waste.
        patches = self.place_db.active_patches() if self.place_db else []
        out: dict[str, dict] = {}
        for direction, yaw in _ABSOLUTE_DIRECTION_YAW.items():
            tx, ty, _ = _offset_location(*xyz, yaw, _STEP_DISTANCE)
            grid = self.world_grid.locate(tx, ty)
            col, row = self._cell_col_row(grid)
            name = None
            ground: list[dict] = []
            refusals: list[dict] = []
            if self.place_db and col is not None:
                known = self.place_db.get_place(col, row)
                name = known.get("name") if known else None
                ground = self.place_db.get_ground(col, row)
                refusals = self.place_db.get_refusals(col, row)
            # Patches are points, not cells (#78) — but sampling only the step
            # TARGET meant a wall three metres away was invisible in this list,
            # because it sat nowhere near the point 15 m out. That is the exact
            # gap #91 fills: a sealed volume the APC cannot see is a seal that
            # changes nothing. Walk the line instead, and say how far along it
            # the first no-go ground begins.
            no_go, at_cm = self._patches_along(patches, xyz, yaw, _STEP_DISTANCE)
            out[direction] = {"cell": _cell_label(grid), "place": name,
                              "ground": ground, "refusals": refusals,
                              "no_go": no_go}
            if at_cm is not None:
                out[direction]["no_go_at_cm"] = at_cm
            seen_ahead = (eyes or {}).get("views", {}).get(direction)
            if seen_ahead:
                out[direction]["seen_ahead"] = seen_ahead
        return out

    def _owned_place_here(self, agent_id: str, name: str, xyz) -> dict | None:
        """The place this agent already owns under this name, if ``xyz`` is in it (#75).

        An owned place is a 9x9 m box, and the row that holds it keys on
        ``(col, row, owner, name)`` — so the *cell* is part of its identity. A
        place near a cell boundary therefore gets a second row the moment its
        owner stands on the other side of that line, and the two rows are the
        same physical thing recorded twice.

        Maren's vegetable truck is the live example: authored at (5,5), recorded
        again at runtime as (6,5), the two anchors **134 cm apart** across the
        boundary at x=-9000. Her prompt listed the truck twice as her two nearest
        places, and the SR41 log resolved 'vegetable truck' to a cell she was not
        standing in on every tick of the run.

        "The same place" is the test already used for arrival — inside the extent
        box — so an APC that is *at* its truck by the schedule's reckoning cannot
        simultaneously be somewhere new by the map's. Returns the owning row, or
        None when this really is somewhere else.
        """
        if self.place_db is None or xyz is None:
            return None
        needle = str(name or "").strip().lower()
        if not needle:
            return None
        for place in self.place_db.all_owned_places():
            if place["owner"] != agent_id or str(place["name"]).strip().lower() != needle:
                continue
            center = self.world_grid.cell_center(place["col"], place["row"])
            if center is None:
                continue
            half = float(place.get("extent_cm") or PLACE_EXTENT_CM) / 2.0
            if (abs(xyz[0] - (center[0] + place["dx"])) <= half
                    and abs(xyz[1] - (center[1] + place["dy"])) <= half):
                return place
        return None

    def _record_place(self, agent_id: str, location, place_name) -> None:
        """Persist an LLM-named place into PlaceDB and the legacy spatial map."""
        name = str(place_name or "").strip()
        xyz = _loc_xyz(location)
        if not name or name.lower() in ("null", "none", "unknown") or xyz is None:
            return
        # Write to PlaceDB (primary store — permanent, compass-structured).
        if self.place_db:
            grid = self.world_grid.locate(xyz[0], xyz[1])
            col, row = self._cell_col_row(grid)
            if col is not None:
                stored = self.place_db.set_name(agent_id, col, row, name, self.world_clock.now_text())
                if stored:
                    logger.info(f"[{agent_id}] place named: '{name}' at {grid.get('key')}")
                else:
                    # Cell already community-named (first name wins). A *different*
                    # name becomes an APC-owned place cell — a named 9x9 m box at an
                    # XY offset from the community anchor (#11.2) — instead of
                    # being silently dropped ("My Home" inside "village square").
                    existing = self.place_db.get_place(col, row)
                    existing_name = ((existing or {}).get("name") or "").strip().lower()
                    if existing_name and existing_name != name.lower():
                        already = self._owned_place_here(agent_id, name, xyz)
                        center = self.world_grid.cell_center(col, row)
                        if already is not None:
                            # Standing in a place this agent already owns under this
                            # name. Nothing to record — and recording it anyway is
                            # what put two "vegetable truck" rows in the SR41 world
                            # (#75), because owned rows key on the cell.
                            logger.debug(
                                "[%s] owned place '%s' already recorded at (%s,%s) — "
                                "standing inside it, not duplicating",
                                agent_id, name, already["col"], already["row"])
                        elif center is not None and self.place_db.add_owned_place(
                                agent_id, col, row, name,
                                dx=xyz[0] - center[0], dy=xyz[1] - center[1]):
                            logger.info(f"[{agent_id}] owned place: '{name}' at {_cell_label(grid)}")
        # Also write to the legacy spatial map (keeps direction previews working).
        smap = self._spatial_map(agent_id)
        smap.ingest(xyz[0], xyz[1], [{"label": name, "confidence": 0.8, "distance": "near"}])
        smap.save(self._agents_dir / agent_id / "spatial_map.json")

    def _stamp_footing(self, agent_id: str, grid: dict | None,
                       seen: dict | None) -> list[dict]:
        """Attach the ground underfoot to the crumb the APC is standing on (#58).

        Footing arrives a phase later than position — the crumb is dropped
        during observation assembly, perception reports the surface afterwards —
        so the newest crumb gets stamped rather than a fresh one appended. Also
        banks the reading as a shared world fact, so the cell is known ground
        for every APC from now on, not just this one on this tick.
        """
        trail = self._breadcrumbs.setdefault(agent_id, [])
        footing = str((seen or {}).get("footing") or "").strip()
        if not footing:
            return list(trail)
        if trail:
            trail[-1]["footing"] = footing
        if self.place_db:
            col, row = self._cell_col_row(grid)
            if col is not None:
                self.place_db.record_ground(agent_id, col, row, footing)
        return list(trail)

    def _travel_fact(self, agent_id: str, location, grid: dict | None = None) -> dict | None:
        """Which way the APC actually travelled to reach this spot (#56), and a
        breadcrumb for the leg it just walked (#58).

        "Turn back the way I came" was unrepresentable: nothing recorded the
        inbound heading, so the model had to guess with the body-relative word
        ``back``, which is measured from a facing it cannot see. This is the
        missing fact, stated in compass terms — the same terms the survey, the
        grid and the place database already use. ``None`` until the APC has
        actually moved; a stationary tick keeps the last real heading rather
        than inventing one from pose jitter.

        One heading is one leg of memory, though, and a detour is several. Every
        real leg also drops a crumb, so the whole way in is on the record and
        the way out is a statement of fact rather than a guess.
        """
        xyz = _loc_xyz(location)
        if xyz is None:
            return self._travel.get(agent_id)
        previous = self._travel_from.get(agent_id)
        self._travel_from[agent_id] = (xyz[0], xyz[1])
        if previous is None:
            self._drop_crumb(agent_id, grid, None, 0.0)
            return self._travel.get(agent_id)
        dx, dy = xyz[0] - previous[0], xyz[1] - previous[1]
        if math.hypot(dx, dy) < _MOVEMENT_START_CM:
            return self._travel.get(agent_id)
        heading = yaw_to_compass(math.degrees(math.atan2(dy, dx)))
        self._travel[agent_id] = {
            "heading": heading,
            "came_from": _OPPOSITE_COMPASS[heading],
            "distance_cm": round(math.hypot(dx, dy), 1),
        }
        self._drop_crumb(agent_id, grid, heading, math.hypot(dx, dy))
        return self._travel[agent_id]

    def _last_move_fact(self, agent_id: str, location) -> dict | None:
        """Did the move we ordered last tick actually happen? (#59)

        The bridge answers "accepted" the instant it takes a walk command, and
        that answer was the only one anybody saw. SR39 ended with four identical
        ticks at (-6013.2, 2609.9): `moved_cm: 0.0`, `result_status: success`,
        same order re-issued each time. Dufus worked out he was wedged before we
        told him — "I'm stuck moving" — while every log line said he was fine.

        Accepted is not moved. This states the achieved displacement against the
        order that asked for it, and says so out loud in the log when a real
        movement order produced nothing. Facts only: what to do about a stalled
        order is the model's call, not ours.
        """
        order = self._last_order.get(agent_id)
        xyz = _loc_xyz(location)
        if not order or xyz is None or order.get("from") is None:
            return None
        moved = math.hypot(xyz[0] - order["from"][0], xyz[1] - order["from"][1])
        fact = {"intent": order.get("intent"), "moved_cm": round(moved, 1),
                "stalled": moved < _MOVEMENT_START_CM}
        want_yaw = order.get("heading_yaw")
        if want_yaw is not None and moved >= _HEADING_DRIFT_MIN_CM:
            went = math.degrees(math.atan2(xyz[1] - order["from"][1],
                                           xyz[0] - order["from"][0]))
            drift = abs((went - want_yaw + 180.0) % 360.0 - 180.0)
            if drift > _HEADING_DRIFT_DEG:
                word = _COMPASS_LETTER_WORD.get(yaw_to_compass(went))
                fact["went"] = {"heading": word, "drift_deg": round(drift)}
                logger.info(
                    "[%s] DRIFT: ordered %s, ended up %s (%.0f deg off, %.1f m) — "
                    "the engine walked a path, not a line", agent_id,
                    order.get("intent"), word, drift, moved / 100.0)
        plan = order.get("plan")
        held = isinstance(plan, dict) and not plan.get("distance_cm")
        if fact["stalled"] and held:
            logger.info(
                "[%s] HELD: %s was not ordered — %s", agent_id,
                order.get("intent"), plan.get("why"))
        elif fact["stalled"]:
            logger.warning(
                "[%s] STALLED: ordered %s, achieved %.1f cm — the bridge accepted "
                "a move that did not happen", agent_id, order.get("intent"), moved)
            # A plan with room in it, an order the bridge took, and no movement:
            # the ground disagreed with the measurement. One of those is
            # ambiguous (somebody walked across the path), so `dead_end` makes a
            # stall wait for a second proof against the same volume before it
            # marks anything (#91).
            self._seal_dead_end(
                agent_id, str(order.get("intent") or ""),
                (order["from"][0], order["from"][1], 0.0),
                order.get("heading_yaw"), "stalled",
                (order.get("plan") or {}).get("reach_cm"))
        fact["tried_here"] = self._record_attempt(
            agent_id, xyz, order.get("intent"), moved)
        # A step that was silently shortened is the bug class rule 12 forbids:
        # the model cannot tell a capped step from a stall unless we say which
        # it was, and why (#86).
        if isinstance(plan, dict) and plan.get("why"):
            fact["plan"] = {"distance_cm": plan.get("distance_cm"),
                            "wanted_cm": plan.get("wanted_cm"),
                            "capped_by": plan.get("capped_by"),
                            "grew": plan.get("grew"),
                            "why": plan["why"]}
        return fact

    def _wedge_fact(self, agent_id: str, last_move: dict | None,
                    directions: dict | None) -> dict | None:
        """How long this APC has been stuck on one spot, and the proven ways out (#65).

        One stalled order is ordinary — you lean on a fence, you pick another
        heading. A *run* of them is the failure mode that costs whole runs: SR39
        spent four ticks on (-6013.2, 2609.9), SR40 eight alternating east and
        southeast between a person and a mailbox. In both, every individual fact
        we showed was true and none of them said *this has been going on*.

        So the run length is itself a fact, and at ``_WEDGE_BUDGET_TICKS`` it
        comes with the escapes already worked out: neighbouring cells somebody
        has actually stood on with good footing, minus the headings that have
        already failed from this spot, minus anything refused. Everything here is
        measured — ``cell_ground`` samples and `_record_attempt`'s tried list —
        and per [[feedback_facts_not_blocking]] it stays a fact. The model still
        chooses; it simply can no longer claim it did not know.

        Returns ``None`` until a stall run is under way, else
        ``{"run": n, "budget": n, "escapes": [{"direction", "footing",
        "samples", "cell"}]}`` with ``escapes`` filled only once the budget is
        spent.
        """
        if not isinstance(last_move, dict) or not last_move.get("intent"):
            return None
        if not last_move.get("stalled"):
            self._stall_run.pop(agent_id, None)
            return None

        run = self._stall_run.get(agent_id, 0) + 1
        self._stall_run[agent_id] = run
        fact: dict = {"run": run, "budget": _WEDGE_BUDGET_TICKS}
        if run < _WEDGE_BUDGET_TICKS:
            return fact

        tried = last_move.get("tried_here") or {}
        escapes = []
        for direction, info in (directions or {}).items():
            # An escape route that runs into ground the body has already proved
            # impassable is not an escape (#91). The wedge sense used to skip
            # only *stated* refusals, so a volume the APC sealed itself two ticks
            # ago could still be offered back as a "known-good way out".
            if direction in tried or info.get("refusals") or info.get("no_go"):
                continue
            for ground in info.get("ground") or []:
                if ground.get("footing") in _GOOD_FOOTING:
                    escapes.append({"direction": direction,
                                    "footing": ground["footing"],
                                    "samples": ground.get("sample_count") or 0,
                                    "cell": info.get("cell")})
                    break
        # Most-walked first: a cell ten footings deep is a surer bet than one
        # somebody clipped the corner of once.
        escapes.sort(key=lambda e: (-e["samples"], e["direction"]))
        fact["escapes"] = escapes
        logger.warning(
            "[%s] WEDGED: %d consecutive stalled orders on one spot (tried: %s). "
            "Known-good ways out: %s", agent_id, run,
            ", ".join(tried) or "nothing yet",
            ", ".join(f"{e['direction']} ({e['footing']})" for e in escapes) or "NONE KNOWN")
        return fact

    def _frontier_fact(self, grid: dict | None) -> dict | None:
        """The size of the map, the shape of what is mapped, and where its edge is (#73).

        Every navigation fact an APC had was one step wide: the eight neighbouring
        cells, and whether each was named. That is enough to answer "where do I put
        my foot" and cannot answer "where should this survey go next", so the choice
        fell to whichever heading the body already pointed — a random walk, and a
        random walk with no sense of extent draws a line.

        SR41's map is the proof. 15 cells surveyed out of a 17x12 grid, and they
        are a strip **7 wide and 2 tall**: rows 5 and 6 are saturated across seven
        columns while rows 4 and 7 hold one cell each. Nothing was malfunctioning.
        Dufus simply never had a fact that said the world has twelve rows in it.

        So three measured things, none of them an instruction: how big the grid is,
        what fraction of it is mapped and the bounding box that map occupies, and
        the nearest unmapped cells that touch mapped ground — by compass bearing
        and distance in cells. Refused cells are excluded; someone already said
        they are not ground to walk into, and the frontier must not re-offer them
        the way plain "unexplored" used to (#59).

        Frontier means *adjacent to mapped ground*, not merely unmapped: an APC
        cannot usefully be sent to the far corner of a grid it has no route to,
        and the edge of the blob is exactly the set of cells that grow it.

        Returns ``None`` when the grid is unbounded or nothing has been mapped yet
        (there is no frontier without a blob), else ``{"cols", "rows", "total",
        "mapped", "extent": {...}, "cells": [{"cell", "direction", "steps"}]}``.
        """
        col, row = self._cell_col_row(grid)
        if col is None or not self.place_db:
            return None
        cols, rows = grid.get("cols"), grid.get("rows")
        if not cols or not rows:
            return None
        mapped = self.place_db.explored_cells()
        if not mapped:
            return None

        refused = {(r["col"], r["row"]) for r in self.place_db.all_refusals()
                   if r.get("col") is not None}
        neighbours = [(dc, dr) for dc in (-1, 0, 1) for dr in (-1, 0, 1)
                      if (dc, dr) != (0, 0)]
        frontier = {
            (c + dc, r + dr)
            for (c, r) in mapped for dc, dr in neighbours
            if (c + dc, r + dr) not in mapped
            and (c + dc, r + dr) not in refused
            and 0 <= c + dc < cols and 0 <= r + dr < rows
        }

        cells = []
        for (fc, fr) in frontier:
            dc, dr = fc - col, fr - row
            if (dc, dr) == (0, 0):
                continue  # the cell underfoot has its own authoritative verdict
            cells.append({"cell": f"{fc},{fr}",
                          "direction": _compass_word(dc, dr),
                          "steps": max(abs(dc), abs(dr))})
        # Nearest first; a stable tiebreak so the list does not reshuffle between
        # ticks and read as new information when nothing has changed.
        cells.sort(key=lambda f: (f["steps"], f["direction"], f["cell"]))
        # One cell per bearing. Sorting by distance alone fills the whole list
        # from whichever side of the blob happens to be closest, which is exactly
        # the input that produced a 7x2 strip — a short list that all points one
        # way is not a choice. Nearest *in each direction* is the same measurement
        # shown so its shape survives the truncation.
        nearest_by_bearing: dict[str, dict] = {}
        for f in cells:
            nearest_by_bearing.setdefault(f["direction"], f)
        cells = sorted(nearest_by_bearing.values(),
                       key=lambda f: (f["steps"], f["direction"]))

        mapped_cols = [c for c, _ in mapped]
        mapped_rows = [r for _, r in mapped]
        return {
            "cols": cols, "rows": rows, "total": cols * rows, "mapped": len(mapped),
            "extent": {"min_col": min(mapped_cols), "max_col": max(mapped_cols),
                       "min_row": min(mapped_rows), "max_row": max(mapped_rows),
                       "width": max(mapped_cols) - min(mapped_cols) + 1,
                       "height": max(mapped_rows) - min(mapped_rows) + 1},
            "cells": cells[:_FRONTIER_LIMIT],
            "frontier_total": len(frontier),
        }

    def _seal_dead_end(self, agent_id: str, direction: str, xyz,
                       yaw: float | None, kind: str,
                       reach_cm: float | None = None,
                       blocker: str = "") -> dict | None:
        """Write down the volume the body just proved it cannot enter (#91).

        This is the step that was missing. Every other piece already existed: the
        engine measures the wall (#90), the plan reports there is no room (#86),
        the wedge sense counts the run (#65), PlaceDB stores no-go patches and the
        prompt reads them back (#78). But a patch was only ever written by the
        *mind* choosing `refuse`, and a wedged mind never chooses it — it is busy
        picking the next heading. So the measurement was taken, stated, acted on
        and thrown away, once per tick, forever. SR50: nine paid decisions on two
        spots, every one of them correct about that instant, all of them ordering
        a heading the body had already disproved minutes earlier.

        The fix is not to stop the APC going that way. Per
        [[feedback_facts_not_blocking]] the mind still chooses. The fix is that
        the world now REMEMBERS: the volume in front is marked where it stands,
        so the memory survives walking away from it, which `_record_attempt`'s
        one-spot ledger deliberately does not.

        Two grades of evidence, and they are not equal (see `dead_end`):
        ``"measured"`` is the engine sweeping this capsule along this heading and
        reporting it does not fit — one is enough. ``"stalled"`` is only that an
        accepted order produced no movement, which a passer-by can cause, so it
        waits for a second proof against the same volume.

        Returns the sealed patch record, or ``None`` when nothing was written
        (no position, no heading, no PlaceDB, or not enough proof yet).
        """
        if xyz is None or yaw is None or not direction or not self.place_db:
            return None

        candidates = self._walls.setdefault(agent_id, [])
        # Locate the proof at a nominal width first — this is only a lookup, to
        # decide whether it belongs to a wall already on the ledger.
        probe_x, probe_y = dead_end.wall_point(
            xyz[0], xyz[1], yaw, reach_cm or 0.0, dead_end.BASE_RADIUS_CM)
        wall = dead_end.find_candidate(candidates, probe_x, probe_y)
        if wall is None:
            wall = {"x": probe_x, "y": probe_y, "radius_cm": dead_end.BASE_RADIUS_CM,
                    "proofs": 0, "headings": [], "kind": kind, "sealed": False}
            candidates.append(wall)
        wall["proofs"] += 1
        wall["headings"].append(direction)
        # A measurement outranks a bare stall: once the engine has read this
        # volume, the wall is measured even if the first proof was a stall.
        if kind == "measured":
            wall["kind"] = "measured"
        wall["radius_cm"] = dead_end.seal_radius(
            wall["proofs"], self._blocked_fraction(agent_id))
        # Keep the wall where it was first seen and push it clear as it widens.
        # Re-placing the circle on every proof splits one wall into a string of
        # them (three headings into one building produced three rows), while
        # leaving it alone lets the growing radius reach back over the APC's own
        # feet — the SR44 failure, where an APC stands in ground it just marked.
        wall["x"], wall["y"] = dead_end.push_clear(
            wall["x"], wall["y"], xyz[0], xyz[1], wall["radius_cm"])

        if not dead_end.should_seal(wall["kind"], wall["proofs"]):
            logger.info(
                "[%s] wall proof %d/%d going %s — not sealed yet", agent_id,
                wall["proofs"], dead_end.PROOFS_TO_SEAL.get(wall["kind"], 2), direction)
            return None

        reason = dead_end.seal_reason(wall["kind"], wall["headings"],
                                      wall["proofs"], reach_cm, blocker)
        self.place_db.refuse_patch(
            agent_id, wall["x"], wall["y"], reason,
            self.world_clock.now_text(), radius_cm=wall["radius_cm"],
            source="measured", proofs=wall["proofs"],
        )
        first_seal = not wall["sealed"]
        wall["sealed"] = True
        logger.warning(
            "[%s] SEALED %s no-go volume r=%.1f m at (%.0f, %.0f) after %d proof(s) "
            "going %s: %s", agent_id, "a new" if first_seal else "a wider",
            wall["radius_cm"] / 100.0, wall["x"], wall["y"], wall["proofs"],
            ", ".join(dict.fromkeys(wall["headings"])), reason)
        return {"x": wall["x"], "y": wall["y"], "radius_cm": wall["radius_cm"],
                "proofs": wall["proofs"], "reason": reason, "new": first_seal}

    def _blocked_fraction(self, agent_id: str) -> float | None:
        """How much of the last probe raster came back solid, if one was read (#91).

        The width of the mark should come from the width of the thing, and the
        raster is the only measurement of that we have. ``None`` when no raster
        was read this tick — never guess a wall wider than what was seen.
        """
        return self._last_raster.get(agent_id)

    def _record_attempt(self, agent_id: str, xyz, intent, moved_cm: float) -> dict:
        """Which headings have already failed from the spot the APC is on (#60).

        SR40 spent eight ticks wedged at (-3200.7, 670.2) alternating east and
        southeast — "east is blocked, try southeast", "southeast is blocked, try
        east" — each decision correct given what it knew, which was only that
        the *immediately previous* order failed. Same shape as SR37's footing
        ping-pong: one tick of memory cannot see a two-item loop from inside it.

        Cleared the moment the APC actually moves, because these headings are
        facts about one spot, not about the world — a mailbox blocks east from
        here and from nowhere else.
        """
        here = (round(xyz[0], 1), round(xyz[1], 1))
        record = self._tried_here.get(agent_id)
        if moved_cm >= _MOVEMENT_START_CM or record is None or record.get("at") != here:
            if moved_cm >= _MOVEMENT_START_CM:
                self._tried_here.pop(agent_id, None)
                return {}
            record = {"at": here, "tried": {}}
            self._tried_here[agent_id] = record
        if intent:
            previous = record["tried"].get(intent)
            record["tried"][intent] = (round(moved_cm, 1) if previous is None
                                       else min(previous, round(moved_cm, 1)))
        return dict(record["tried"])

    def _open_walk_plan(self, agent_id: str, observation: dict, direction: str,
                        legs: list[float], plan: dict) -> None:
        """Remember a grown step so the hops after the first are walked for free."""
        xyz = _loc_xyz(observation.get("location"))
        yaw = self._direction_yaw(observation, direction)
        if xyz is None or yaw is None:
            return
        self._walk_plans[agent_id] = {
            "from": (xyz[0], xyz[1]), "z": xyz[2], "yaw": yaw,
            "intent": direction, "legs": legs, "leg": 0, "ticks": 0,
            "along": 0.0, "idle": 0,
            "nearby": self._nearby_ids.get(agent_id),
        }
        logger.info(
            "[%s] walk plan: %s %.1f m in %d hops of %.0f m",
            agent_id, direction, plan["distance_cm"] / 100.0, len(legs),
            _STEP_DISTANCE / 100.0)

    def _has_active_walk(self, agent: Agent) -> bool:
        """Whether this APC is part-way through a grown step (#86)."""
        return agent.agent_id in self._walk_plans

    def _end_walk_plan(self, agent_id: str, why: str) -> None:
        """Drop the plan and buy the APC a full cognition tick to react."""
        if self._walk_plans.pop(agent_id, None) is not None:
            self._force_next_decide.add(agent_id)
            logger.info("[%s] walk plan ended: %s", agent_id, why)

    def _pulse_walk(self, agent: Agent) -> dict:
        """One hop of a grown step — bridge only, no model call (#86).

        The cheap state read and the forward probe are the whole cost. Anything
        that makes the next hop a decision rather than a continuation ends the
        plan and hands the tick back to cognition:

        * something ahead the body must reckon with (it does not fit, it is
          inside the standoff, or it can move on its own);
        * the walk drifting off the straight line it was ordered along — which
          is the navmesh routing around something, the SR47 failure, caught
          after one hop instead of after fifty metres;
        * anyone arriving or leaving nearby, so a plan can never walk an APC
          past someone it should have noticed;
        * the hops running out, or the plan simply going on too long.

        ``_last_order`` is deliberately NOT touched here: the achieved-versus-
        ordered check (#59) and the heading-drift fact then measure the WHOLE
        grown step against the one order the model actually gave.
        """
        agent_id = agent.agent_id
        plan = self._walk_plans.get(agent_id)
        if plan is None:
            return {"agent_id": agent_id, "action": "idle", "walk": True}
        plan["ticks"] += 1

        reader = getattr(self.bridge, "get_character_state", None)
        state = reader(agent.bound_unreal_actor_name) if callable(reader) else {}
        xyz = _loc_xyz((state or {}).get("location"))
        if xyz is None:
            self._end_walk_plan(agent_id, "no position")
            agent.mark_ticked(self._agents_dir)
            return {"agent_id": agent_id, "action": "idle", "walk": True}

        if plan["ticks"] > _WALK_PLAN_MAX_TICKS:
            self._end_walk_plan(agent_id, f"{plan['ticks']} ticks is long enough")
            agent.mark_ticked(self._agents_dir)
            return {"agent_id": agent_id, "action": "idle", "walk": True}

        nearby = self._nearby_agent_ids(agent_id, xyz)
        if plan["nearby"] is not None and nearby != plan["nearby"]:
            self._end_walk_plan(agent_id, "someone came or went")
            agent.mark_ticked(self._agents_dir)
            return {"agent_id": agent_id, "action": "idle", "walk": True}

        # How far along the ordered line are we, and how far off it?
        fx, fy = plan["from"]
        rad = math.radians(plan["yaw"])
        ux, uy = math.cos(rad), math.sin(rad)
        dx, dy = xyz[0] - fx, xyz[1] - fy
        along = dx * ux + dy * uy
        off = abs(-dx * uy + dy * ux)
        if off > _LEG_DRIFT_CM:
            self._end_walk_plan(
                agent_id, f"walked {off / 100.0:.1f} m off the line it was sent along")
            agent.mark_ticked(self._agents_dir)
            return {"agent_id": agent_id, "action": "idle", "walk": True}

        # Probe the rest of THIS hop, not a fixed 5 m of it (#90).
        remaining = max(plan["legs"][plan["leg"]] - along, _AHEAD_TRACE_CM)
        trace = self._probe_ahead(agent, min(remaining, _PLAN_PROBE_MAX_CM))
        if trace.get("hit"):
            category = _classify_blocker(trace.get("actor_name", ""),
                                         trace.get("actor_class", ""),
                                         trace.get("signals"))
            distance = float(trace.get("distance_cm", 0.0) or 0.0)
            if (trace.get("fits") is False or distance <= _STANDOFF_CM
                    or category in _MOBILE_BLOCKERS):
                self._end_walk_plan(
                    agent_id, f"{category} {distance:.0f} cm ahead")
                agent.mark_ticked(self._agents_dir)
                return {"agent_id": agent_id, "action": "idle", "walk": True}

        # Still short of this hop? Let the body keep walking to it — unless it
        # has stopped making ground, which is a wedge and belongs to cognition.
        # Without this a plan could sit silent against a wall for its whole tick
        # budget, which is the exact failure #65 exists to make loud.
        target_cm = plan["legs"][plan["leg"]]
        if target_cm - along > _LEG_ARRIVE_CM:
            gained = along - plan.get("along", 0.0)
            plan["along"] = along
            plan["idle"] = plan.get("idle", 0) + 1 if gained < _STUCK_PROGRESS_CM else 0
            if plan["idle"] >= _STUCK_TICKS:
                self._end_walk_plan(agent_id, "stopped making ground on this hop")
                agent.mark_ticked(self._agents_dir)
                return {"agent_id": agent_id, "action": "idle", "walk": True}
            agent.mark_ticked(self._agents_dir)
            return {"agent_id": agent_id, "action": "walking", "walk": True,
                    "leg": plan["leg"] + 1, "total": len(plan["legs"])}

        plan["leg"] += 1
        plan["idle"] = 0
        plan["along"] = along
        if plan["leg"] >= len(plan["legs"]):
            self._end_walk_plan(agent_id, "all hops walked")
            agent.mark_ticked(self._agents_dir)
            return {"agent_id": agent_id, "action": "idle", "walk": True}

        target = _offset_location(fx, fy, plan["z"], plan["yaw"],
                                  plan["legs"][plan["leg"]])
        result = self.bridge.execute_action(
            agent.bound_unreal_actor_name, {"type": "walk_to", "location": target})
        logger.info("[%s] walk plan: hop %d/%d %s", agent_id, plan["leg"] + 1,
                    len(plan["legs"]), plan["intent"])
        agent.mark_ticked(self._agents_dir)
        return {"agent_id": agent_id, "action": "walk_to", "walk": True,
                "leg": plan["leg"] + 1, "total": len(plan["legs"]), "result": result}

    def _note_movement_order(self, agent_id: str, action: dict, observation: dict) -> None:
        """Remember the movement we just ordered, so next tick can check it."""
        if action.get("type") not in _MOVEMENT_ACTIONS:
            self._last_order.pop(agent_id, None)
            return
        xyz = _loc_xyz(observation.get("location"))
        intent = str(action.get("direction") or action.get("target_location")
                     or action.get("type") or "")
        self._last_order[agent_id] = {
            "intent": intent,
            "from": (xyz[0], xyz[1]) if xyz else None,
            "plan": observation.get("_move_plan"),
            "heading_yaw": (self._direction_yaw(observation, action["direction"])
                            if action.get("direction") else None),
        }

    def _drop_crumb(self, agent_id: str, grid: dict | None,
                    heading: str | None, distance_cm: float) -> None:
        """Record one leg walked: where it ended, and the heading that got there.

        Per *leg*, not per cell. Cells are 30 m districts and SR37's whole
        ping-pong happened inside two of them — collapsing the trail to cell
        changes would have rendered that loop as one motionless crumb, which is
        exactly the blindness this fact exists to remove.
        """
        trail = self._breadcrumbs.setdefault(agent_id, [])
        previous = trail[-1] if trail else None
        trail.append({
            "cell": _cell_label(grid),
            "heading": heading,
            "distance_cm": round(distance_cm, 1),
            "footing": None,
        })
        del trail[:-_BREADCRUMB_LEN]
        # Two consecutive legs in opposite headings = walked in and straight
        # back out. The pocket entered (the previous leg's end) is the trap;
        # counting it per run is the #26 "louder fact", not a blocker.
        if (isinstance(previous, dict) and heading and previous.get("heading")
                and _OPPOSITE_COMPASS.get(heading) == previous["heading"]):
            counts = self._bounces.setdefault(agent_id, {})
            trap = previous.get("cell") or "?"
            counts[trap] = counts.get(trap, 0) + 1

    def _direction_yaw(self, observation: dict, direction: str) -> float | None:
        """The world yaw a direction word points along, or None if unresolvable.

        A compass word ("north") is absolute and means the same thing on every
        tick. A body-relative word ("back") is measured from the avatar's
        current facing, which changes as it walks and turns — so the same word
        can mean opposite headings two decisions apart (#56).
        """
        name = str(direction or "").strip().lower()
        absolute = _ABSOLUTE_DIRECTION_YAW.get(name)
        if absolute is not None:
            return absolute
        yaw = _yaw_of(observation.get("rotation"))
        offset = _DIRECTION_YAW_OFFSET.get(name)
        if yaw is None or offset is None:
            return None
        return yaw + offset

    def _direction_target(self, observation: dict, direction: str,
                          distance_cm: float | None = None) -> list[float] | None:
        """Resolve a direction word to a world location ``distance_cm`` away.

        ``distance_cm`` is the move plan's answer (#86). It defaults to the
        nominal step only so callers asking a *map* question — which cell lies
        one step that way — keep the fixed 15 m they mean; the cell a heading
        names must not move because the body's step got shorter.
        """
        xyz = _loc_xyz(observation.get("location"))
        if xyz is None:
            return None
        yaw = self._direction_yaw(observation, direction)
        if yaw is None:
            return None
        step = _STEP_DISTANCE if distance_cm is None else float(distance_cm)
        return _offset_location(*xyz, yaw, step)

    @staticmethod
    def _patches_along(patches: list[dict], xyz, yaw: float,
                       limit_cm: float) -> tuple[list[dict], float | None]:
        """No-go patches lying on the line ahead, and how far along the first one starts.

        A point test at the step target answers "is the place I mean to end up
        forbidden". It cannot answer "is there forbidden ground between here and
        there", and the second question is the one that matters when the mark is
        two metres wide and the step is fifteen (#91).

        Returns the patches hit, nearest first, and the distance to the first —
        ``(<empty>, None)`` when the line is clear.
        """
        hits: list[tuple[float, dict]] = []
        seen: set = set()
        d = 0.0
        while d <= limit_cm:
            px, py, _ = _offset_location(*xyz, yaw, d)
            for patch in patches:
                key = patch.get("id", id(patch))
                if key in seen:
                    continue
                if math.hypot(px - patch["x"], py - patch["y"]) <= patch["radius_cm"]:
                    seen.add(key)
                    hits.append((d, patch))
            d += _SCAN_STEP_CM
        if not hits:
            return [], None
        hits.sort(key=lambda h: h[0])
        return [p for _, p in hits], round(hits[0][0], 1)

    def _scan_ahead(self, xyz, yaw: float, limit_cm: float) -> dict:
        """Look down one heading on the SHARED map: how far is proven, where must we stop?

        The lizard brain's half of the move plan (#86), and it costs no engine
        call — every fact is already in PlaceDB, filed by whoever walked there.
        Two different answers come out of one walk along the line:

        * ``open_run_cm`` — how far the ground ahead has been *stood on* with
          good footing, cell after cell, with nothing refused in the way. This is
          the reason a step may grow: crossing done ground should not cost one
          paid decision per 15 m.
        * ``stop_short_cm`` — the distance to the first ground somebody refused
          (a no-go patch, a refused cell). This is the reason a step must shrink,
          and it is the SR46 bug directly: patches refused accurately and then
          walked into anyway, because the only step available was wider than the
          patch.

        Facts only ([[feedback_facts_not_blocking]]): a refusal caps the step's
        LENGTH, never its heading, and never cancels the move. An APC that means
        to go that way still goes that way — it stops at the edge.
        """
        out = {"open_run_cm": 0.0, "stop_short_cm": None, "stop_reason": ""}
        if xyz is None or yaw is None or not self.place_db:
            return out
        patches = self.place_db.active_patches() or []
        cells: dict[tuple, dict] = {}
        open_run = 0.0
        open_ended = False
        d = _SCAN_STEP_CM
        while d <= limit_cm:
            px, py, _ = _offset_location(*xyz, yaw, d)
            hit = next((q for q in patches
                        if math.hypot(px - q["x"], py - q["y"]) <= q["radius_cm"]), None)
            if hit is not None:
                out["stop_short_cm"] = d - _SCAN_STEP_CM
                out["stop_reason"] = f"no-go patch ({hit.get('reason') or 'refused'})"
                break
            col, row = self._cell_col_row(self.world_grid.locate(px, py))
            if col is None:
                open_ended = True          # off the authored grid: unknown, not refused
                d += _SCAN_STEP_CM
                continue
            known = cells.get((col, row))
            if known is None:
                known = {"refusals": self.place_db.get_refusals(col, row),
                         "ground": self.place_db.get_ground(col, row)}
                cells[(col, row)] = known
            if known["refusals"]:
                out["stop_short_cm"] = d - _SCAN_STEP_CM
                out["stop_reason"] = "refused cell"
                break
            walked = any(str(g.get("footing")) in _GOOD_FOOTING for g in known["ground"])
            if not walked:
                open_ended = True          # never stood in: not proven, not forbidden
            if not open_ended:
                open_run = d
            d += _SCAN_STEP_CM
        out["open_run_cm"] = open_run
        return out

    def _plan_move(self, agent, observation: dict, direction: str,
                   action: dict) -> dict:
        """Compute this step's length from world evidence (#86).

        The model chose the heading; everything about the distance is decided
        here, from what the map and the body already know. Four inputs, each
        skipped when it was not measured rather than guessed at:

        * the shared map ahead (``_scan_ahead``) — grows or caps the step;
        * the body-box probe (#81) — caps it, but only when the probe was
          looking the way we are about to walk. ``_probe_ahead`` traces along the
          avatar's *facing*; a clearance measured east says nothing about north,
          and using it anyway would shorten every sideways step for no reason;
        * walkable ground itself (#101) — caps it on the same terms, for the
          eight named compass directions the radar's ring actually measured;
        * the model's coarse ``distance`` word, when it offered one.
        """
        yaw = self._direction_yaw(observation, direction)
        xyz = _loc_xyz(observation.get("location"))
        if yaw is None:
            return {"distance_cm": _STEP_DISTANCE, "wanted_cm": _STEP_DISTANCE,
                    "capped_by": None, "grew": False, "why": "", "stop_reason": ""}
        scan = self._scan_ahead(xyz, yaw, move_plan.MAX_STEP_CM)

        # Ask the engine how far this body can travel that way, and make the
        # answer the step (#90). Not a constant capped by a measurement — the
        # measurement itself. `_STEP_DISTANCE` survives only as the fallback for
        # when nothing could be measured, and a step taken that way says so.
        reach = self._look_along(agent, observation, yaw, _PLAN_PROBE_MAX_CM)

        # #101: air can read clear well past where walkable ground itself ends
        # (SR56's slab, SR56's carport hole). Only a named compass direction
        # lines up exactly with one of the radar's eight fixed sectors — a
        # body-relative word ("left") does not, and is left unmeasured here
        # rather than guessed from the nearest sector.
        ground_cm = None
        heading_word = str(direction or "").strip().lower()
        for h in observation.get("radar") or []:
            if h.get("heading") == heading_word and h.get("ground_cm") is not None:
                ground_cm = max(float(h["ground_cm"]) - dead_end.BASE_RADIUS_CM, 0.0)
                break

        plan = move_plan.plan_step(
            prefer=action.get("distance"),
            reach_cm=reach,
            stop_short_cm=scan["stop_short_cm"],
            ground_cm=ground_cm,
            open_run_cm=scan["open_run_cm"],
            standoff_cm=_STANDOFF_CM,
            nominal_cm=_STEP_DISTANCE,
        )
        plan["stop_reason"] = scan["stop_reason"]
        plan["reach_cm"] = reach
        return plan

    def _look_along(self, agent, observation: dict, yaw: float,
                    distance_cm: float) -> float | None:
        """Ask the engine how far this body can travel along one heading (#90).

        Turns the probe to the heading rather than turning the character, and the
        engine sweeps the APC's own capsule along that rotation — so the answer is
        a measurement of the actual line of travel, not an estimate from rays.

        Returns free travel in cm: the sweep's ``clearance_cm`` when something was
        struck, the full ``distance_cm`` when nothing was. ``None`` means **not
        measured** — never "clear" — and the plan falls back to the fixed step and
        labels it a guess. Silence and open ground must never look the same.
        """
        volume = getattr(self.bridge, "forward_volume", None)
        facing = _yaw_of(observation.get("rotation"))
        if not callable(volume) or facing is None or self._volume_probe_unavailable:
            return None
        offset = (yaw - facing + 180.0) % 360.0 - 180.0
        try:
            result = volume(agent.bound_unreal_actor_name, distance_cm,
                            yaw_offset_deg=offset) or {}
        except Exception as e:
            logger.warning("[%s] plan probe %+.0f failed: %s",
                           agent.agent_id, offset, e)
            return None
        if not result.get("success") or "fits" not in result:
            return None
        if result.get("fits") is True:
            return float(distance_cm)
        return float(result.get("clearance_cm", 0.0) or 0.0)

    def _execute_routed_walk(self, agent: Agent, action: dict, observation: dict) -> dict:
        """Send a remembered place to the existing engine pathfinder.

        Grid coordinates index the place store; they never become waypoints.
        Physical arrival uses the same place extent as the agenda. Engine path
        failures remain facts for cognition and permit local recovery next tick.
        """
        agent_id = agent.agent_id
        name = action["target_location"]
        end = self._resolve_place_endpoint(agent_id, name)
        if end is None:
            self._routes.pop(agent_id, None)
            return self.bridge.execute_action(agent.bound_unreal_actor_name, action)

        xyz = _loc_xyz(observation.get("location"))
        if xyz is None:
            return {"status": "error", "error": f"cannot approach {name}: position unavailable"}
        if route_planner.at_place(end, (xyz[0], xyz[1])):
            self._routes.pop(agent_id, None)
            return {"status": "accepted", "action": "idle", "note": f"arrived at {name}"}

        route = self._routes.get(agent_id)
        if (route is None or route["destination"] != name
                or route["target_xy"] != end["xy"]
                or route["extent_cm"] != end["extent_cm"] or observation.get("stuck")):
            route = {"destination": name, "target_xy": end["xy"],
                     "extent_cm": end["extent_cm"]}
            self._routes[agent_id] = route
            logger.info("[%s] approaching place '%s' at %s", agent_id, name, end["xy"])

        # Target the anchor, not a point backed off from it: the latter can sit
        # across a wall and also stops short by the engine's acceptance radius.
        target = [end["xy"][0], end["xy"][1], xyz[2]]
        observation["_resolved_target"] = target
        result = self.bridge.execute_action(agent.bound_unreal_actor_name,
                                            {**action, "location": target})
        if isinstance(result, dict):
            path = result.get("path")
            route["path_status"] = path
            if result.get("error") or path == "none" or result.get("moved") is False:
                route["path_status"] = "none"
                result["note"] = f"cannot reach {name} from here; inspect another approach"
            elif path == "partial":
                result["note"] = f"incomplete path to {name}; destination not yet reached"
            else:
                result.setdefault("note", f"approaching {name}")
        return result

    def _execute_world_action(self, agent: Agent, action: dict, observation: dict) -> dict:
        """Execute a validated action in Unreal, resolving direction-relative movement.

        ``wander`` is a forward step; ``walk_to`` with a ``direction`` becomes a
        walk to a world location computed from the agent's current facing.
        """
        action = self._resolve_action_actor_refs(action)
        t = action.get("type")

        if t == "observe":
            return {"status": "success", "image_path": observation.get("image_path"), "action": "observe"}

        # Sweep observation (#7/#11.1 live half): no bridge-side handler needed —
        # composed from existing primitives (set_facing + capture + perceive +
        # ingest_compass), the same path the wake look-around uses.
        if t == "observe_heading":
            return self._execute_sweep_observe(agent, action, observation)

        # Keep ordinary travel focused on the named goal. A blocked/incomplete
        # engine path or a stuck body permits the model's local recovery step.
        schedule = observation.get("schedule") or {}
        scheduled_place = str(schedule.get("place") or "").strip()
        travel_route = self._routes.get(agent.agent_id) or {}
        travel_blocked = (travel_route.get("destination") == scheduled_place
                          and travel_route.get("path_status") in ("none", "partial"))
        if (schedule.get("status") == "travel" and scheduled_place
                and not travel_blocked and not observation.get("stuck")
                and not isinstance(getattr(agent, "active_interrupt", None), dict)
                and (t == "wander" or (t == "walk_to" and action.get("direction")))):
            action = {"type": "walk_to", "target_location": scheduled_place}
            t = "walk_to"

        if t == "wander" or (t == "walk_to" and action.get("direction")):
            direction = action.get("direction") or "forward"
            # How far this step goes is the lizard brain's call, from the map and
            # the body — not a constant, and not something the model is asked to
            # get right (#86).
            plan = self._plan_move(agent, observation, direction, action)
            observation["_move_plan"] = plan
            self._walk_plans.pop(agent.agent_id, None)
            if plan["distance_cm"] <= 0.0:
                logger.info(f"[{agent.agent_id}] move plan: no step {direction} — "
                            f"{plan['why']}")
                # The engine just swept this body along this heading and found
                # less than one step of travel. That reading is the whole point
                # of #91 and it used to be thrown away the moment it was logged:
                # SR50 re-ordered northwest, north and northeast into the same
                # wall on two separate spots because nothing wrote it down. Only
                # a *physical* refusal is the body's own proof — "refused
                # ground" means the step stopped short of somebody's stated
                # no-go, which is already recorded and must not be re-marked as
                # a wall.
                sealed = None
                if plan.get("capped_by") != "refused ground":
                    sealed = self._seal_dead_end(
                        agent.agent_id, direction,
                        _loc_xyz(observation.get("location")),
                        self._direction_yaw(observation, direction),
                        "measured", plan.get("reach_cm"),
                        (observation.get("blocker") or {}).get("actor_name", ""))
                note = f"no room to step {direction}: {plan['why']}"
                if sealed:
                    note += (f" — marked as no-go ground "
                             f"({sealed['radius_cm'] / 100:.1f} m across)")
                return {"status": "accepted", "action": "idle", "note": note}
            if plan["capped_by"] or plan["grew"]:
                logger.info(
                    f"[{agent.agent_id}] move plan: {direction} "
                    f"{plan['distance_cm'] / 100:.1f} m "
                    f"(wanted {plan['wanted_cm'] / 100:.1f} m"
                    + (f", capped by {plan['capped_by']}" if plan["capped_by"] else ", grew")
                    + ")")
            # A grown step is never handed over whole (#86). Cut it into hops of
            # one nominal step and order only the first; `_pulse_walk` walks the
            # rest with no model call. The engine only ever sees a distance the
            # fixed 15 m step always walked correctly.
            legs = move_plan.leg_distances(plan["distance_cm"], _STEP_DISTANCE)
            if len(legs) > 1:
                self._open_walk_plan(agent.agent_id, observation, direction,
                                     legs, plan)
            target = self._direction_target(observation, direction, legs[0])
            if target is None and t == "wander":
                # No yaw available — legacy random step so wander never dead-ends.
                import random
                xyz = _loc_xyz(observation.get("location"))
                if xyz:
                    target = [xyz[0] + random.uniform(-2500, 2500), xyz[1] + random.uniform(-2500, 2500), xyz[2]]
            if target is None:
                return {"status": "accepted", "action": "idle",
                        "note": f"cannot resolve direction '{direction}' — no location/facing"}
            # Record where the direction word actually pointed, so the decision
            # log can show the heading it produced (#55).
            action["_resolved_target"] = target
            # `action` here is a COPY (`_resolve_action_actor_refs`), so this key
            # never reaches the caller and the movement trace has been silently
            # falling back to `action["location"]` — which a direction walk does
            # not have. The observation is not copied, so it is the honest place
            # to leave it, and the trace reads it from there.
            observation["_resolved_target"] = target
            result = self.bridge.execute_action(
                agent.bound_unreal_actor_name, {"type": "walk_to", "location": target}
            )
            if result.get("error"):
                return {"status": "accepted", "action": "idle",
                        "note": f"walk {direction} blocked: {result.get('error')}"}
            return result

        # Resolve the named place and let the engine find the physical path.
        if (t == "walk_to" and isinstance(action.get("target_location"), str)
                and not action.get("location") and not action.get("target_actor")):
            return self._execute_routed_walk(agent, action, observation)

        # walk_to a known character: stop a personal-space standoff short of them
        # (B7b) instead of walking into their face. The bridge's move-to-actor
        # drives the whole gap closed, and the ~9 s decision cadence means the
        # reflex stop in _observe_agent can't catch an approach that closes it
        # within a single tick — so terminate the approach short at the command
        # level. Engine-agnostic: compute a stop point and reuse walk_to location.
        # Falls through unchanged if either position is unknown (e.g. the player).
        if (t == "walk_to" and action.get("target_actor")
                and not action.get("location") and not action.get("direction")):
            me = _loc_xyz(observation.get("location"))
            tgt = None
            if me is not None:
                tf = self.bridge.get_character_transform(action["target_actor"])
                tgt = _loc_xyz((tf or {}).get("location"))
            if me is not None and tgt is not None:
                dist = math.hypot(tgt[0] - me[0], tgt[1] - me[1])
                if dist <= _STANDOFF_CM:
                    return {"status": "accepted", "action": "idle",
                            "note": "already at greeting distance — did not close in"}
                f = (dist - _STANDOFF_CM) / dist
                action = {k: v for k, v in action.items() if k != "target_actor"}
                action["location"] = [me[0] + (tgt[0] - me[0]) * f,
                                      me[1] + (tgt[1] - me[1]) * f, tgt[2]]

        return self.bridge.execute_action(agent.bound_unreal_actor_name, action)

    def _execute_sweep_observe(self, agent: Agent, action: dict, observation: dict) -> dict:
        """Execute one sweep observation: turn in place to the absolute yaw,
        capture, perceive, and ingest the landmarks into the shared PlaceDB
        under that compass direction.

        Reuses the wake look-around's primitives (``set_facing`` +
        ``capture_view`` + the vision perceiver) — no engine-side handler
        exists or is needed. Degrades per-heading: a failed turn/capture/
        perception returns an error result and records nothing, but the sweep
        state machine has already advanced, so one bad heading never wedges
        the sweep. Runs only in the sequential phases (single-socket bridge;
        one heading = one tick).
        """
        agent_id = agent.agent_id
        yaw = float(action.get("yaw", 0.0))
        direction = yaw_to_compass(yaw)
        turn = self.bridge.set_facing(agent.bound_unreal_actor_name,
                                      observation.get("location"), yaw)
        if turn.get("error"):
            return {"status": "error", "action": "observe_heading", "direction": direction,
                    "error": f"turn failed: {turn['error']}"}
        time.sleep(0.25)  # let the rotated frame render before capturing
        image_path = self.bridge.capture_view(
            agent.bound_unreal_actor_name, agent_id, self._agents_dir, f"sweep_{direction}"
        )
        if not image_path:
            return {"status": "error", "action": "observe_heading", "direction": direction,
                    "error": "capture failed"}
        seen = self.perceiver.perceive(image_path, observation.get("known_characters") or [])
        self._record_perception_pair(
            agent_id, image_path, seen,
            location=observation.get("location"), yaw=yaw,
            grid=observation.get("grid"),
            world_time=observation.get("world_time"), context="survey_sweep")
        if seen.get("error"):
            return {"status": "error", "action": "observe_heading", "direction": direction,
                    "error": f"perception failed: {seen['error']}"}
        self._note_eyes(agent_id, observation.get("location"), yaw, seen)
        landmarks = seen.get("landmarks") or []
        col, row = self._cell_col_row(observation.get("grid"))
        if self.place_db and col is not None and landmarks:
            self.place_db.ingest_compass(agent_id, col, row, direction, landmarks)
        active = self._cell_sweeps.get(agent_id)
        if active is not None:
            here = _loc_xyz(observation.get("location"))
            active.setdefault("views", []).append({
                "direction": direction,
                "yaw": yaw,
                "image_path": image_path,
                "caption": seen.get("caption", ""),
                # Where the frame was actually taken — the only evidence that a
                # composite belongs to the cell it is filed under (#55).
                "at": [here[0], here[1]] if here else None,
                "landmarks": landmarks,
                "characters": seen.get("characters", []),
            })
        return {"status": "success", "action": "observe_heading", "direction": direction,
                "yaw": yaw, "landmarks": len(landmarks), "image_path": image_path,
                "caption": seen.get("caption", "")}

    def _pulse_sweep(self, agent: Agent) -> dict:
        """One tick for an agent mid-sweep — deterministic, no perception LLM.

        Builds a minimal observation (position + grid; no vision diff gate,
        which a deterministic step doesn't need), then continues the active
        sweep. When the sweep just finished (breadcrumb dropped), reports it
        and lets the next tick resume the normal perceive/decide path — the
        #10 sequencer directive re-issues the routine on its own.
        """
        agent_id = agent.agent_id
        observation = self.bridge.get_observation(
            agent.bound_unreal_actor_name, agent_id, self._agents_dir
        )
        grid, place = self._grid_and_place(agent_id, observation.get("location"))
        observation["grid"] = grid
        observation["place"] = place
        observation["world_time"] = self.world_clock.now_text()

        action = self._dispatch_active_survey(agent, observation)
        if action is None:
            agent.mark_ticked(self._agents_dir)
            return {"agent_id": agent_id, "action": "sweep_done", "grid": grid, "sweep": True}

        agent.set_active_interrupt_preemptible(False, self._agents_dir)
        result = self._execute_world_action(agent, action, observation)
        self._note_survey_travel_result(agent_id, action, result)
        if action.get("type") == "observe_heading":
            self._finish_survey_heading(agent, result)
        agent.mark_ticked(self._agents_dir)
        return {"agent_id": agent_id, "action": action, "result": result,
                "grid": grid, "sweep": True}

    def _mission_wants_tick(self, agent: Agent) -> bool:
        """Whether the survey mission (#96) drives this APC's tick.

        No when a checkpoint is owed (`_force_next_decide`): that one tick
        belongs to the LLM — it is the entire model budget of a surveyed cell.
        No in Play mode (#102) either: the mission is paused, not cancelled.
        """
        return (self.mode == "survey" and agent.mission == "survey"
                and agent.has_unreal_binding
                and agent.agent_id not in self._force_next_decide)

    def _pulse_mission(self, agent: Agent) -> dict:
        """One survey-mission tick (#96): pick the next cell, put it to work.

        Deterministic and bridge-only, like `_pulse_sweep`. Code chooses the
        target (center-out ring order over the world grid, skipping answered
        and unreachable ground) and offers it as an ordinary survey
        interruption — from there the existing machinery does everything:
        travel to the cell (with the wedge/abandon handling), the four-heading
        sweep, the breadcrumb, and the `_force_next_decide` debt that becomes
        this cell's one LLM checkpoint. A cell whose travel is abandoned is
        marked unreachable in the spatial map and the next tick simply picks
        the next cell — the mission never ends on a wedge.
        """
        agent_id = agent.agent_id
        observation = self.bridge.get_observation(
            agent.bound_unreal_actor_name, agent_id, self._agents_dir
        )
        grid, place = self._grid_and_place(agent_id, observation.get("location"))
        observation["grid"] = grid
        observation["place"] = place
        observation["world_time"] = self.world_clock.now_text()

        target = self._mission_next_target(agent_id)
        if target is None:
            # Every cell is swept, refused, or proven unreachable. Loud, once —
            # a completed mission must never look like an idle wedge (rule 12).
            if agent_id not in self._mission_complete:
                self._mission_complete.add(agent_id)
                logger.warning(
                    f"[{agent_id}] SURVEY MISSION COMPLETE — every grid cell is "
                    f"swept, refused, or marked unreachable"
                )
                self._pie_activity(agent_id, "survey mission complete")
            agent.mark_ticked(self._agents_dir)
            return {"agent_id": agent_id, "action": "mission_complete",
                    "grid": grid, "mission": True}
        self._mission_complete.discard(agent_id)

        col, row = target
        offer = self._offer_survey_interrupt(
            agent, observation, target=(col, row), source="mission",
            reason=f"survey mission: ({col},{row}) is the next unsurveyed cell",
        )
        if isinstance(offer, dict) and offer.get("_survey_pending"):
            logger.info(f"[{agent_id}] mission: next survey target ({col},{row})")
            self._pie_activity(agent_id, f"mission -> survey cell ({col},{row})")
            action = self._dispatch_active_survey(agent, observation)
        else:
            action = offer
        if action is None:
            # Offer refused or the survey resolved instantly — nothing to walk.
            # Not silent: the next tick re-selects, and a repeat is visible.
            logger.warning(
                f"[{agent_id}] mission: survey of ({col},{row}) produced no "
                f"step this tick — will re-select next tick"
            )
            agent.mark_ticked(self._agents_dir)
            return {"agent_id": agent_id, "action": "mission_no_step",
                    "target": [col, row], "grid": grid, "mission": True}

        agent.set_active_interrupt_preemptible(False, self._agents_dir)
        result = self._execute_world_action(agent, action, observation)
        self._note_survey_travel_result(agent_id, action, result)
        if action.get("type") == "observe_heading":
            self._finish_survey_heading(agent, result)
        agent.mark_ticked(self._agents_dir)
        return {"agent_id": agent_id, "action": action, "result": result,
                "grid": grid, "mission": True}

    def _mission_next_target(self, agent_id: str) -> tuple[int, int] | None:
        """The next cell the survey mission should work, or None = complete.

        Done = swept or refused (both are answered ground). Unreachable = the
        APC's own spatial map says the cell cannot be entered (written by the
        abandoned-travel path), or its composite already exists — the same
        gate `_sweep_step` starts with, checked here so the mission can never
        select a cell the sweep would instantly decline, tick after tick.
        """
        if self.place_db is None or not self.world_grid.has_bounds:
            return None
        b = self.world_grid.bounds
        probe = self.world_grid.locate(b["min_x"], b["min_y"])
        origin = self._cell_col_row(self.world_grid.locate(
            (b["min_x"] + b["max_x"]) / 2.0, (b["min_y"] + b["max_y"]) / 2.0))
        if origin[0] is None:
            return None
        done = set(self.place_db.swept_cells())
        done |= {(r["col"], r["row"]) for r in self.place_db.all_refusals()}
        smap = self._spatial_map(agent_id)

        def unreachable(cell: tuple[int, int]) -> bool:
            center = self.world_grid.cell_center(*cell)
            if center is None:
                return True
            if smap.is_blocked(self.world_grid.locate(center[0], center[1])["key"]):
                return True
            return self._survey_visual_is_current(agent_id, *cell)

        return survey_mission.next_target(
            probe["cols"], probe["rows"], origin, done, unreachable)

    def _mission_fact(self, agent_id: str) -> dict | None:
        """Coverage + next target, shown to a mission APC at its checkpoint."""
        if self.place_db is None or not self.world_grid.has_bounds:
            return None
        b = self.world_grid.bounds
        probe = self.world_grid.locate(b["min_x"], b["min_y"])
        target = self._mission_next_target(agent_id)
        return {
            "kind": "survey",
            "swept": len(self.place_db.swept_cells()),
            "total": probe["cols"] * probe["rows"],
            "next_target": list(target) if target else None,
        }

    def _mission_start_placement(self, agent: Agent) -> dict | None:
        """Where a mission APC starts the run: the edge of covered ground (#96).

        As coverage grows, the first target cell moves further from the town,
        and a run that begins with a ten-minute commute across surveyed ground
        buys nothing the map does not already hold. So at sim start — and only
        then; mid-run the body always walks — the APC is placed at the center
        of a *swept* cell adjacent to its first target: ground the survey has
        stood on, one step from the work. Fresh worlds (no swept neighbor) and
        APCs already within a cell of the target place nothing and walk as
        before. Returns ``{"location", "cell", "target"}`` or None.
        """
        if self.place_db is None:
            return None
        target = self._mission_next_target(agent.agent_id)
        if target is None:
            return None
        tf = self.bridge.get_character_transform(agent.bound_unreal_actor_name)
        xyz = _loc_xyz(tf.get("location"))
        if xyz is None:
            return None
        here = self._cell_col_row(self.world_grid.locate(xyz[0], xyz[1]))
        if (here[0] is not None
                and max(abs(here[0] - target[0]), abs(here[1] - target[1])) <= 1):
            return None
        swept = set(self.place_db.swept_cells())
        neighbors = [(target[0] + dc, target[1] + dr)
                     for dc in (-1, 0, 1) for dr in (-1, 0, 1)
                     if (dc, dr) != (0, 0)]
        candidates = [c for c in neighbors if c in swept]
        if not candidates:
            return None

        def walked(cell: tuple[int, int]) -> bool:
            return any(str(g.get("footing")) in _GOOD_FOOTING
                       for g in self.place_db.get_ground(*cell))

        # Prefer a neighbor somebody has actually stood in with good footing —
        # a teleport is the one move the navmesh never checks.
        candidates.sort(key=lambda c: (not walked(c), c))
        center = self.world_grid.cell_center(*candidates[0])
        if center is None:
            return None
        return {"location": [center[0], center[1], xyz[2]],
                "cell": candidates[0], "target": target}

    async def restart_day(self) -> dict:
        """Restart the sim from morning — a fresh day that keeps the world.

        Stops the sim if running, re-anchors the world clock to its configured
        morning start, and clears each agent's per-run runtime state (daily
        schedule, last activity, timers) so a new morning plan regenerates on the
        next start. Memories and place cells are intentionally **preserved** — the
        world keeps everything it has learned; only the day resets. (Contrast
        reset_agents, which also wipes memories + spatial maps.)
        """
        was_running = self.running
        if was_running:
            await self.stop_simulation()

        if not self.agents:
            self._load_agents(None)
            self._bind_agents()

        self.world_clock.reset()   # now_text() -> configured morning start

        agent_ids = []
        for agent in self.agents.values():
            agent.reset_runtime_state(self._agents_dir)
            agent_ids.append(agent.agent_id)
        self._cell_sweeps.clear()

        logger.info(
            f"=== DAY RESTART === {len(agent_ids)} agent(s) reset to morning "
            f"({self.world_clock.now_text()}); memories + place cells preserved"
            f"{', sim stopped first' if was_running else ''}"
        )
        return {
            "status": "day_reset",
            "world_time": self.world_clock.now_text(),
            "stopped_simulation": was_running,
            "agents": agent_ids,
        }

    async def reset_agents(self) -> dict:
        """Reset agents to their run-start state for reproducible re-runs.

        Stops the sim if running, teleports each agent back to its recorded
        start transform, clears per-run timers and episodic recall, restores
        memories from memory.seed.json (or empties them), and deletes spatial maps.
        """
        was_running = self.running
        if was_running:
            await self.stop_simulation()

        if not self.agents:
            self._load_agents(None)
            self._bind_agents()
        if not self.agents or not self._agents_dir:
            return {"status": "error", "error": "No agents loaded — is Unreal connected?"}

        results = []
        for agent in self.agents.values():
            entry: dict = {"agent_id": agent.agent_id}

            if agent.start_location and agent.has_unreal_binding:
                result = self.bridge.teleport(
                    agent.bound_unreal_actor_name, agent.start_location, agent.start_rotation
                )
                ok = result.get("success") is True or result.get("status") == "success"
                entry["teleported"] = ok
                if not ok:
                    entry["teleport_error"] = result.get("error") or "unknown error"
            else:
                entry["teleported"] = False
                entry["teleport_error"] = (
                    "no Unreal binding" if agent.start_location else "no start transform recorded"
                )

            agent.reset_runtime_state(self._agents_dir)
            entry["memories"] = self.memory.reset_memories(agent.agent_id)
            entry["episodes"] = self._episodic(agent.agent_id).reset()

            map_path = self._agents_dir / agent.agent_id / "spatial_map.json"
            if map_path.exists():
                map_path.unlink()
                entry["spatial_map"] = "deleted"

            results.append(entry)

        self._spatial.clear()
        self._last_cell.clear()
        self._frontier_failures.clear()
        self._scene_skips.clear()
        self._nearby_ids.clear()
        self._volume_probe_unavailable = False
        self._last_pos.clear()
        self._travel_from.clear()
        self._travel.clear()
        self._breadcrumbs.clear()
        self._last_order.clear()
        self._walk_plans.clear()
        self._tried_here.clear()
        self._stall_run.clear()
        self._walls.clear()
        self._last_raster.clear()
        self._last_ground.clear()
        self._footing_recoveries.clear()
        self._no_progress.clear()
        self._routes.clear()
        self._cell_sweeps.clear()
        self._live_pos.clear()
        self.bridge.clear_scene_cache()

        failures = [r["agent_id"] for r in results if not r["teleported"]]
        logger.info(
            f"=== AGENTS RESET === {len(results)} agent(s)"
            f"{', sim stopped first' if was_running else ''}"
            f"{', teleport FAILED for: ' + ', '.join(failures) if failures else ''}"
        )
        return {"status": "reset", "stopped_simulation": was_running, "agents": results}

    async def reset_world_places(self) -> dict:
        """Wipe the shared place-cell DB so the world map starts from scratch.

        Unlike reset_agents (which preserves geography for reproducible re-runs),
        this clears place_cells, place_observations, and agent_visits entirely.
        Stops the sim first if running so no tick is mid-write. Agent JSON state
        (memories, spatial maps) is left untouched — run reset_agents for that.
        """
        was_running = self.running
        if was_running:
            await self.stop_simulation()

        # Resolve the DB even when the sim has never started this session.
        if self.place_db is None:
            if not self.agents:
                self._load_agents(None)
            if not self._agents_dir:
                return {"status": "error", "error": "No agents loaded — cannot locate world_places.db"}
            self.place_db = PlaceDB(self._agents_dir.parent / "world_places.db")

        removed = self.place_db.reset()
        logger.info(
            f"=== WORLD PLACES WIPED === place_cells={removed['place_cells']}, "
            f"place_observations={removed['place_observations']}, agent_visits={removed['agent_visits']}"
            f"{', sim stopped first' if was_running else ''}"
        )
        return {"status": "reset", "stopped_simulation": was_running, "removed": removed}

    async def regrid_world(self, level: str, origin_x: float, origin_y: float) -> dict:
        """Apply a logical lattice origin and invalidate all grid-keyed state.

        Regridding is deliberately destructive to derived geography: PlaceDB
        rows/images, per-agent spatial maps, rendered route maps, and in-memory
        routes/sweeps all refer to the old cell keys. Authored world positions,
        agent starts, schedules, and ordinary memories are preserved.
        """
        if not (math.isfinite(origin_x) and math.isfinite(origin_y)):
            return {"status": "error", "error": "origin_x/origin_y must be finite numbers"}

        worlds_root = self.worlds_dir.resolve()
        world_dir = (worlds_root / str(level)).resolve()
        if (world_dir == worlds_root or worlds_root not in world_dir.parents
                or not world_dir.is_dir()):
            return {"status": "error", "error": f"Unknown or unsafe world '{level}'"}
        grid_path = world_dir / "world_grid.json"
        if not grid_path.is_file():
            return {"status": "error", "error": f"{level} has no world_grid.json"}
        try:
            raw = json.loads(grid_path.read_text(encoding="utf-8"))
        except Exception as e:
            return {"status": "error", "error": f"Could not read world_grid.json: {e}"}
        if not raw.get("bounds"):
            return {"status": "error", "error": f"{level} has no bounded grid"}

        was_running = self.running
        if was_running:
            await self.stop_simulation()

        db_path = world_dir / "world_places.db"
        removed = {}
        if db_path.exists():
            target_db = (self.place_db if self.place_db is not None
                         and self.place_db._path.resolve() == db_path.resolve()
                         else PlaceDB(db_path))
            removed = target_db.reset()

        deleted_spatial_maps = 0
        deleted_route_maps = 0
        agents_dir = world_dir / "agents"
        if agents_dir.is_dir():
            for path in agents_dir.glob("*/spatial_map.json"):
                path.unlink()
                deleted_spatial_maps += 1
            for path in agents_dir.glob("*/observations/route_map.png"):
                path.unlink()
                deleted_route_maps += 1

        raw["origin_x"] = float(origin_x)
        raw["origin_y"] = float(origin_y)
        temp_path = grid_path.with_suffix(".json.tmp")
        temp_path.write_text(json.dumps(raw, indent=2), encoding="utf-8")
        temp_path.replace(grid_path)
        updated_grid = WorldGrid.load(grid_path)

        if self._agents_dir is not None and self._agents_dir.parent.resolve() == world_dir:
            self.world_grid = updated_grid
        self._spatial.clear()
        self._last_cell.clear()
        self._last_grid_place.clear()
        self._frontier_failures.clear()
        self._routes.clear()
        if (self._agents_dir is not None
                and self._agents_dir.parent.resolve() == world_dir):
            for agent in self.agents.values():
                result = agent.cancel_interrupts(
                    "survey", "survey cancelled because the world grid changed", self._agents_dir,
                    self.world_clock.now_text(),
                )
                if result.get("cancelled_count"):
                    self._record_interrupt_event(agent, "cancelled", result.get("last_interrupt"))
                    if result.get("active") is not None:
                        self._record_interrupt_event(agent, "activated", result.get("active"))
        self._cell_sweeps.clear()
        self._live_pos.clear()

        logger.info(
            f"=== WORLD REGRID === level={level} logical_origin=({origin_x:.0f},{origin_y:.0f}) "
            f"places={removed} spatial_maps={deleted_spatial_maps}"
            f"{', sim stopped first' if was_running else ''}"
        )
        return {
            "status": "regridded", "level": level,
            "origin_x": updated_grid.origin_x, "origin_y": updated_grid.origin_y,
            "effective_origin": list(updated_grid.origin() or ()),
            "stopped_simulation": was_running, "removed": removed,
            "deleted_spatial_maps": deleted_spatial_maps,
            "deleted_route_maps": deleted_route_maps,
        }

    def resync(self) -> dict:
        """Re-query the world and rebind agents without a full stop/restart cycle."""
        was_paused = self.paused
        self.paused = True

        pre_bindings = {
            a.agent_id: a.bound_unreal_actor_label
            for a in self.agents.values()
        }

        active_ids = list(self.agents.keys()) if self.agents else None
        self._load_agents(active_ids)
        bound_count = self._bind_agents()

        current_level = self.bridge.get_current_level()

        added, removed, rebound, skipped_levels = [], [], [], []
        all_ids = set(pre_bindings) | set(self.agents)
        for aid in all_ids:
            was_in = aid in pre_bindings
            now_in = aid in self.agents
            if not was_in and now_in:
                added.append(aid)
            elif was_in and not now_in:
                removed.append(aid)
            elif was_in and now_in:
                old_label = pre_bindings[aid]
                new_label = self.agents[aid].bound_unreal_actor_label
                if old_label != new_label:
                    rebound.append({"agent_id": aid, "old_label": old_label, "new_label": new_label})

        self.paused = was_paused
        logger.info(f"Resync complete — level='{current_level}' bound={bound_count}")
        return {
            "status": "resynced",
            "level": current_level,
            "bound_count": bound_count,
            "added": added,
            "removed": removed,
            "rebound": rebound,
            "skipped_levels": skipped_levels,
        }

    def capture_start_transforms(self) -> dict:
        """Adopt current bound APC transforms as explicit reset/start points.

        This is intentionally operator-triggered: silently refreshing on every
        start would capture a wandered runtime position during a same-PIE rerun.
        Use after placing APCs in the editor (and while the sim is stopped).
        """
        if self.running:
            return {"status": "error", "error": "Stop the simulation before capturing starts"}
        if not self.agents:
            self._load_agents(None)
            self._bind_agents()
        if not self._agents_dir:
            return {"status": "error", "error": "No agents loaded — is Unreal connected?"}

        captured, skipped = [], []
        for agent in self.agents.values():
            if not agent.has_unreal_binding:
                skipped.append({"agent_id": agent.agent_id, "reason": "no Unreal binding"})
                continue
            transform = self.bridge.get_character_transform(agent.bound_unreal_actor_name) or {}
            if not transform.get("location"):
                skipped.append({"agent_id": agent.agent_id, "reason": "no transform"})
                continue
            agent.update_start_transform(transform["location"], transform.get("rotation"),
                                         self._agents_dir)
            captured.append(agent.agent_id)
        logger.info(f"Captured APC start transforms: {captured}; skipped={skipped}")
        return {"status": "captured", "captured": captured, "skipped": skipped}

    # Director commands

    def list_agents(self) -> list[dict]:
        return [self._agent_summary(a) for a in self.agents.values()]

    def inspect_agent(self, agent_id: str) -> dict:
        a = self.agents.get(agent_id)
        if not a:
            return {"error": f"Agent '{agent_id}' not loaded"}
        agenda_execution = self._agenda_execution_for(a)
        agenda_doc, _source = self._agenda_document(
            a, agenda_execution.get("day") or planner.day_of(self.world_clock.now_text()),
            generate=False,
        )
        return {
            "agent_id":        a.agent_id,
            "unreal_actor_name": a.unreal_actor_name,
            "bound_unreal_actor_name": a.bound_unreal_actor_name,
            "bound_unreal_actor_label": a.bound_unreal_actor_label,
            "blueprint_class": a.blueprint_class,
            "tier":            a.tier,
            "is_active":       a.is_active,
            "is_busy":         a.is_busy,
            "current_goal":    a.current_goal,
            "allowed_actions": a.allowed_actions,
            "active_interrupt": a.active_interrupt,
            "interrupt_queue": a.interrupt_queue,
            "last_interrupt": a.last_interrupt,
            "authored_agenda": copy.deepcopy(getattr(a, "authored_agenda", None)),
            "agenda_errors": list(getattr(a, "agenda_errors", []) or []),
            "agenda_execution": copy.deepcopy(agenda_execution),
            "agenda_context": (agenda.context(
                agenda_doc, agenda_execution,
                active_interrupt=getattr(a, "active_interrupt", None),
            ) if isinstance(agenda_doc, dict) and agenda_execution else None),
            "survey_progress": self._survey_progress(a),
            "state":           a.state,
        }

    def set_agent_goal(self, agent_id: str, goal: str) -> dict:
        a = self.agents.get(agent_id)
        if not a:
            return {"error": f"Agent '{agent_id}' not loaded"}
        a.set_goal(goal, self._agents_dir)
        logger.info(f"[{agent_id}] Goal updated -> '{goal}'")
        return {"status": "updated", "agent_id": agent_id, "goal": goal}

    def _interrupt_resume_context(self, agent: Agent) -> dict:
        """Snapshot the current schedule directive from cached, observed state.

        An interruption request must not query Unreal or generate a new daily
        plan.  When a prior observe tick gives us position/place facts, reuse
        the same model-free directive resolver that powers the cognition gate.
        """
        route = self._routes.get(agent.agent_id) or {}
        schedule = {}
        agenda_now = None
        pos = self._live_pos.get(agent.agent_id)
        if pos is not None:
            cached_grid, cached_place = self._last_grid_place.get(agent.agent_id, (None, []))
            grid = cached_grid or self.world_grid.locate(pos["x"], pos["y"])
            observation = {
                "world_time": self.world_clock.now_text(),
                "location": {"x": pos["x"], "y": pos["y"], "z": 0.0},
                "grid": grid,
                "place": cached_place,
            }
            directive = self._existing_schedule_directive(agent, observation)
            if isinstance(directive, dict):
                schedule = dict(directive)
                agenda_now = copy.deepcopy((schedule.get("agenda") or {}).get("right_now"))
                schedule.pop("agenda", None)
        return {
            "current_goal": agent.current_goal,
            "schedule": schedule,
            "agenda": agenda_now,
            "route_destination": route.get("destination"),
        }

    def request_interrupt(self, agent_id: str, *, kind: str, source: str, reason: str,
                          priority: int = None, payload: dict = None,
                          preemptible: bool = True) -> dict:
        """Offer a generic interruption without changing goals or schedule state."""
        agent = self.agents.get(agent_id)
        if agent is None:
            return {"status": "error", "error": f"Agent '{agent_id}' not loaded"}
        for name, value in (("kind", kind), ("source", source), ("reason", reason)):
            if not isinstance(value, str) or not value.strip():
                return {"status": "error", "error": f"{name} must be a non-empty string"}
        if priority is not None and (isinstance(priority, bool) or not isinstance(priority, int)
                                     or not 0 <= priority <= 1000):
            return {"status": "error", "error": "priority must be an integer from 0 to 1000"}
        if payload is None:
            payload = {}
        if not isinstance(payload, dict):
            return {"status": "error", "error": "payload must be an object"}
        if not isinstance(preemptible, bool):
            return {"status": "error", "error": "preemptible must be a boolean"}

        requested_at = self.world_clock.now_text()
        try:
            record = interruptions.make_record(
                interrupt_id=uuid.uuid4().hex,
                kind=kind.strip(), source=source.strip(), reason=reason.strip(),
                priority=priority, requested_at=requested_at, payload=payload,
                resume_context=self._interrupt_resume_context(agent),
                preemptible=preemptible,
            )
        except ValueError:
            return {"status": "error", "error": "interrupt request is not JSON-safe"}
        result = agent.offer_interrupt(record, self._agents_dir, activated_at=requested_at)
        self._record_offer_events(agent, record, result)
        return {
            "status": "requested", "agent_id": agent_id,
            "transition": result.get("transition"),
            "active_interrupt": result.get("active"),
            "interrupt_queue_count": len(result.get("queue") or []),
        }

    @staticmethod
    def _chat_payload(record: dict | None) -> dict | None:
        """Return a valid direct-chat payload owned by an interruption."""
        if not isinstance(record, dict) or record.get("kind") not in {
                "operator_chat", "operator_direction"}:
            return None
        payload = record.get("payload")
        chat = payload.get("chat") if isinstance(payload, dict) else None
        if not isinstance(chat, dict) or chat.get("state") not in {"open", "guiding"}:
            return None
        if not isinstance(chat.get("messages"), list):
            return None
        return chat

    def _has_open_chat(self, agent: Agent) -> bool:
        chat = self._chat_payload(getattr(agent, "active_interrupt", None))
        return bool(chat and chat.get("state") == "open")

    def _pause_for_open_chat(self, agent: Agent) -> None:
        """Halt physical movement whenever a queued chat receives attention."""
        if (not self._has_open_chat(agent) or self.bridge is None
                or not agent.has_unreal_binding):
            return
        self.bridge.execute_action(agent.bound_unreal_actor_name, {"type": "stop"})
        self._set_activity(agent, "chatting")

    async def start_chat(self, agent_id: str, source: str) -> dict:
        """Open a durable, movement-frozen direct conversation with one APC."""
        return await self._run_tick_entry(
            f"chat_start:{agent_id}", lambda: self._start_chat_impl(agent_id, source)
        )

    async def _start_chat_impl(self, agent_id: str, source: str) -> dict:
        agent = self.agents.get(agent_id)
        if agent is None:
            return {"status": "error", "error": f"Agent '{agent_id}' not loaded"}
        if not isinstance(source, str) or not source.strip():
            return {"status": "error", "error": "source must be a non-empty string"}
        existing = self._chat_payload(agent.active_interrupt)
        if existing and existing.get("state") == "open":
            return {"status": "open", "agent_id": agent_id,
                    "active_interrupt": agent.active_interrupt}

        source = source.strip()
        result = self.request_interrupt(
            agent_id, kind="operator_chat", source=source,
            reason=f"{source} opened a direct conversation.", priority=200,
            payload={"chat": {"state": "open", "messages": []}},
            preemptible=False,
        )
        active = result.get("active_interrupt")
        if (isinstance(active, dict) and active.get("kind") == "operator_chat"
                and active.get("source") == source):
            self._pause_for_open_chat(agent)
            result["status"] = "open"
        else:
            result["status"] = "queued"
        return result

    async def send_chat_message(self, agent_id: str, message: str) -> dict:
        """Append one operator turn and obtain a durable in-character reply."""
        return await self._run_tick_entry(
            f"chat_message:{agent_id}",
            lambda: self._send_chat_message_impl(agent_id, message),
        )

    async def _send_chat_message_impl(self, agent_id: str, message: str) -> dict:
        agent = self.agents.get(agent_id)
        if agent is None:
            return {"status": "error", "error": f"Agent '{agent_id}' not loaded"}
        if not isinstance(message, str) or not message.strip():
            return {"status": "error", "error": "message must be a non-empty string"}
        message = message.strip()
        if len(message) > 2000:
            return {"status": "error", "error": "message must be 2000 characters or fewer"}
        active = agent.active_interrupt
        chat = self._chat_payload(active)
        if not chat or chat.get("state") != "open" or active.get("kind") != "operator_chat":
            return {"status": "error", "error": "Agent has no open direct chat"}

        updated = copy.deepcopy(active)
        updated_chat = updated["payload"]["chat"]
        operator_turn = {"role": "operator", "text": message,
                         "at": self.world_clock.now_text()}
        proposed = [*updated_chat["messages"], operator_turn][-50:]
        context = updated.get("resume_context") or {}
        memories = self.memory.get_relevant_memories(agent_id)
        reply = await asyncio.to_thread(self.llm.chat, agent, proposed, context, memories)
        if not isinstance(reply, str) or not reply.strip():
            return {"status": "error", "error": "The APC model did not return a reply"}
        reply = reply.strip()[:4000]
        proposed.append({"role": "agent", "text": reply,
                         "at": self.world_clock.now_text()})
        updated_chat["messages"] = proposed[-50:]
        if not agent.replace_active_interrupt(updated, self._agents_dir):
            return {"status": "error", "error": "Chat changed before the reply could be saved"}
        return {"status": "replied", "agent_id": agent_id, "reply": reply,
                "active_interrupt": agent.active_interrupt}

    async def guide_from_chat(self, agent_id: str, direction: str) -> dict:
        """Convert an open chat into temporary actionable operator guidance."""
        return await self._run_tick_entry(
            f"chat_guide:{agent_id}",
            lambda: self._guide_from_chat_impl(agent_id, direction),
        )

    async def _guide_from_chat_impl(self, agent_id: str, direction: str) -> dict:
        agent = self.agents.get(agent_id)
        if agent is None:
            return {"status": "error", "error": f"Agent '{agent_id}' not loaded"}
        if not isinstance(direction, str) or not direction.strip():
            return {"status": "error", "error": "direction must be a non-empty string"}
        direction = direction.strip()
        if len(direction) > 2000:
            return {"status": "error", "error": "direction must be 2000 characters or fewer"}
        active = agent.active_interrupt
        chat = self._chat_payload(active)
        if not chat or chat.get("state") != "open" or active.get("kind") != "operator_chat":
            return {"status": "error", "error": "Agent has no open direct chat"}
        updated = copy.deepcopy(active)
        updated["kind"] = "operator_direction"
        updated["reason"] = f"Temporary direction from {updated['source']}: {direction}"
        updated["payload"]["chat"]["state"] = "guiding"
        updated["payload"]["chat"]["direction"] = direction
        updated["preemptible"] = False
        if not agent.replace_active_interrupt(updated, self._agents_dir):
            return {"status": "error", "error": "Chat changed before guidance could be saved"}
        self._record_interrupt_event(agent, "guiding", agent.active_interrupt)
        return {"status": "guiding", "agent_id": agent_id,
                "active_interrupt": agent.active_interrupt}

    async def end_chat(self, agent_id: str) -> dict:
        """Release chat/direction ownership and resume the captured prior work."""
        return await self._run_tick_entry(
            f"chat_end:{agent_id}", lambda: self._end_chat_impl(agent_id)
        )

    async def _end_chat_impl(self, agent_id: str) -> dict:
        agent = self.agents.get(agent_id)
        if agent is None:
            return {"status": "error", "error": f"Agent '{agent_id}' not loaded"}
        active = agent.active_interrupt
        if self._chat_payload(active) is None:
            return {"status": "error", "error": "Agent has no active chat or guidance"}
        result = self._terminate_active_interrupt(
            agent, "resolved", "operator released APC to resume prior work",
            self.world_clock.now_text(),
        )
        return {"status": "resumed", "agent_id": agent_id,
                "active_interrupt": result.get("active"),
                "last_interrupt": result.get("last_interrupt"),
                "interrupt_queue_count": len(result.get("queue") or [])}

    def resolve_interrupt(self, agent_id: str, status: str, outcome: str) -> dict:
        """Terminally resolve the one active interruption and expose its successor."""
        agent = self.agents.get(agent_id)
        if agent is None:
            return {"status": "error", "error": f"Agent '{agent_id}' not loaded"}
        if not isinstance(status, str) or status not in interruptions.TERMINAL:
            return {"status": "error", "error": "status must be a terminal interruption status"}
        if not isinstance(outcome, str) or not outcome.strip():
            return {"status": "error", "error": "outcome must be a non-empty string"}
        if agent.active_interrupt is None:
            return {"status": "error", "error": "Agent has no active interruption"}
        result = self._terminate_active_interrupt(
            agent, status, outcome.strip(), self.world_clock.now_text(),
        )
        return {
            "status": status, "agent_id": agent_id,
            "active_interrupt": result.get("active"),
            "interrupt_queue_count": len(result.get("queue") or []),
            "last_interrupt": result.get("last_interrupt"),
        }

    def generate_world_grid(self, cell_size: float = 3000.0, padding: float = 800.0) -> dict:
        """Compute the fixed world grid from the current level's actor positions.

        Scans every actor, takes the min/max x/y plus padding as the world
        bounds, writes ``worlds/<level>/world_grid.json``, and swaps the live
        grid in place. Needs the editor open with PIE stopped (editor-world
        scan). Lived in the MCP tool until #3/2.4 moved it here so the runner
        (the bridge's sole owner) can serve it over HTTP.

        ``cell_size`` default is 3000 cm (30 m) — a grid cell is a *district*
        that holds several ~9 m place cells, not a place-sized tile (the 4 m
        default made grid cells ≈ place cells, collapsing the hierarchy).
        """
        level = self.bridge.get_current_level()
        if not level:
            return {"status": "error",
                    "error": "Could not determine current level — is Unreal running?"}

        actors = self.bridge.get_level_actors()
        points = [a["location"][:2] for a in actors
                  if isinstance(a.get("location"), list) and len(a["location"]) >= 2]
        if not points:
            return {"status": "error",
                    "error": "No actor positions returned — is the editor open (and PIE stopped)?"}

        xs, ys = [p[0] for p in points], [p[1] for p in points]
        bounds = {
            "min_x": min(xs) - padding, "min_y": min(ys) - padding,
            "max_x": max(xs) + padding, "max_y": max(ys) + padding,
        }
        path = self.worlds_dir / level / "world_grid.json"
        path.parent.mkdir(parents=True, exist_ok=True)
        # A regrid invalidates any previous image_bounds calibration — write
        # only the new grid; the capture below re-derives the calibration.
        path.write_text(
            json.dumps({"cell_size": cell_size, "bounds": bounds,
                        "origin_x": 0.0, "origin_y": 0.0}, indent=2),
            encoding="utf-8",
        )
        self.world_grid = WorldGrid(cell_size=cell_size, bounds=bounds)

        # Registration shot (#18): shoot the world map from the MAP_Camera pawn
        # framed to the fresh bounds. Best-effort — a world without the pawn
        # still gets its grid; the failure is reported, never swallowed.
        shot = map_capture.capture_world_map(
            self.bridge, level, bounds, path,
            images_dir=self.worlds_dir.parent / "web_ui" / "images",
        )
        return {
            "status": "generated",
            "level": level,
            "path": str(path),
            "actors_scanned": len(points),
            "bounds": bounds,
            "grid": self.world_grid.describe(),
            "map_capture": shot,
        }

    # Helpers

    def _record_perception_pair(self, agent_id: str, image_path, seen: dict | None, *,
                                location=None, yaw=None, grid: dict | None = None,
                                world_time: str | None = None,
                                context: str = "tick") -> None:
        """Append one image+label line to the agent's perception log (#79).

        Every perceived frame already costs a VLM call; this keeps its answer.
        The line lands in ``observations/perception_log.jsonl`` next to the PNG
        it labels — the training pair the corpus exists to collect
        (project_dufus_vlm_training_corpus). ``last_perception.json`` stays the
        overwritten latest-only debug surface; this file only grows. A failed
        perception is recorded with its ``error`` (the dataset builder filters;
        the sim does not hide misses), and a failed write warns and degrades
        the tick, exactly like perception itself.
        """
        if not self._agents_dir or not image_path or not isinstance(seen, dict):
            return
        xyz = _loc_xyz(location)
        line = {
            "recorded_at": datetime.now(timezone.utc).isoformat(),
            "sim_run": self.sim_run_id,
            "agent_id": agent_id,
            "world_time": world_time,
            "image": Path(image_path).name,
            "context": context,
            "heading": yaw_to_compass(float(yaw)) if yaw is not None else None,
            "at": [round(xyz[0], 1), round(xyz[1], 1)] if xyz else None,
            "cell": _cell_label(grid) if grid else None,
            "model": seen.get("model"),
            "caption": seen.get("caption", ""),
            "footing": seen.get("footing", ""),
            "ground_ahead": seen.get("ground_ahead", ""),
            "path_ahead": seen.get("path_ahead", ""),
            "landmarks": seen.get("landmarks") or [],
            "characters": seen.get("characters") or [],
        }
        if seen.get("error"):
            line["error"] = seen["error"]
        try:
            path = self._agents_dir / agent_id / "observations" / "perception_log.jsonl"
            path.parent.mkdir(parents=True, exist_ok=True)
            with path.open("a", encoding="utf-8") as f:
                f.write(json.dumps(line) + "\n")
        except Exception as e:
            logger.warning(f"[{agent_id}] could not record perception pair: {e}")

    def _save_perception_evidence(self, agent_id: str, observation: dict, seen: dict) -> None:
        """Persist the latest structured VLM output so live misses are inspectable."""
        if not self._agents_dir:
            return
        path = self._agents_dir / agent_id / "last_perception.json"
        payload = {
            "recorded_at": datetime.now(timezone.utc).isoformat(),
            "world_time": observation.get("world_time"),
            "image_path": observation.get("image_path"),
            "model": seen.get("model"),
            "caption": seen.get("caption", ""),
            "landmarks": seen.get("landmarks") or [],
            "characters": seen.get("characters") or [],
            "error": seen.get("error"),
        }
        try:
            tmp = path.with_suffix(".tmp")
            tmp.write_text(json.dumps(payload, indent=2), encoding="utf-8")
            tmp.replace(path)
        except Exception as e:
            logger.warning(f"[{agent_id}] could not save perception evidence: {e}")

    def _record_live_pos(self, agent_id: str, observation: dict) -> None:
        """Remember the agent's last observed position + facing (#18 live map).

        Written on every observe tick from data already in hand — no extra
        engine traffic. A positionless tick (no transform yet) records
        nothing; the previous fix stays until fresher data arrives.
        """
        xyz = _loc_xyz(observation.get("location"))
        if xyz is None:
            return
        self._live_pos[agent_id] = {
            "x": xyz[0], "y": xyz[1],
            "yaw": _yaw_of(observation.get("rotation")),
        }

    def agent_positions(self) -> list[dict]:
        """Last observed position per active agent — the live /map dots (#18).

        Returns ``[{agent_id, x, y, yaw, col, row}, ...]`` (col/row None on an
        unbounded grid). Agents never observed this run are absent — the map
        only shows what the sim has actually seen, never a guess.
        """
        out = []
        for a in self.agents.values():
            p = self._live_pos.get(a.agent_id)
            if p is None or not a.is_active:
                continue
            col, row = self._cell_col_row(self.world_grid.locate(p["x"], p["y"]))
            out.append({"agent_id": a.agent_id, "x": p["x"], "y": p["y"],
                        "yaw": p["yaw"], "col": col, "row": row})
        return out

    def _agent_summary(self, a: Agent) -> dict:
        agenda_execution = self._agenda_execution_for(a)
        agenda_task = next((state for state in agenda_execution.get("tasks", [])
                            if state.get("status") in {"active", "interrupted"}), None)
        return {
            "agent_id":          a.agent_id,
            "unreal_actor_name": a.unreal_actor_name,
            "bound_unreal_actor_name": a.bound_unreal_actor_name,
            "bound_unreal_actor_label": a.bound_unreal_actor_label,
            "tier":              a.tier,
            "is_active":         a.is_active,
            "is_busy":           a.is_busy,
            "current_goal":      a.current_goal,
            "last_tick_time":    a.state.get("last_tick_time"),
            "active_interrupt": a.active_interrupt,
            "agenda_task": copy.deepcopy(agenda_task),
            "agenda_source": agenda_execution.get("source"),
            "survey_progress": self._survey_progress(a),
            "interrupt_queue_count": len(a.interrupt_queue),
        }

    def _resolve_action_actor_refs(self, action: dict) -> dict:
        """Translate a character reference in an action target into the bound
        Unreal actor name the bridge needs.

        The LLM only ever knows agents by their **display name** (that is all
        known_characters exposes), so a targeted action arrives as
        ``target_actor="Maren"`` — not the actor "APC_Maren_BP" the engine wants.
        This is the reverse of known_characters: match the reference against each
        agent's display name, actor label, or id (case-insensitively) and swap in
        the bound actor name. Non-matches (e.g. the human player) pass through.
        """
        resolved = dict(action)
        for key in ("target", "target_actor"):
            value = resolved.get(key)
            if isinstance(value, str):
                actor = self._actor_name_for(value)
                if actor:
                    resolved[key] = actor
        return resolved

    def _actor_name_for(self, ref: str) -> str | None:
        """Resolve a character reference (display name / actor label / agent id)
        to its bound Unreal actor name, case-insensitively; None if no match."""
        key = ref.strip().lower()
        if not key:
            return None
        for a in self.agents.values():
            if not a.has_unreal_binding:
                continue
            if key in {a.agent_id.lower(), a.display_name.lower(),
                       (a.bound_unreal_actor_label or "").lower()}:
                return a.bound_unreal_actor_name
        return None
