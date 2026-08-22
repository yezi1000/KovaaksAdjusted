"""Post-run report: everything the analysis window renders, serializable."""

from __future__ import annotations

import json
from dataclasses import dataclass, field, asdict
from datetime import datetime, timedelta
from pathlib import Path

import numpy as np

from ..stats.models import Run
from ..telemetry.trace import MouseTrace, ResampleCache
from .movement import (apply_shot_outcomes, click_phase_metrics,
                       segment_flicks, directional_bias, region_deficits,
                       movement_heatmap, MIN_FLICK_DEG, YAW_DEG_PER_COUNT)
from .notable import find_notable_moments


# ---- input health: the one gate on every microstructure claim -------------
# Lives HERE, in the module that owns RunReport, because analysis/insights.py
# and analysis/sens.py both import report — so this is the only place all
# three (and the GUI) can share. It previously existed as three separate
# inline copies, and every surface that forgot one told the user something
# the other surfaces refused to say about the same run.
JITTER_BAD_MS = 2.0
# Below this, the SAMPLING PERIOD starts destroying the features themselves.
# Measured rather than assumed: synthetic flicks with known geometry, sampled
# at 1000 / 500 / 250 / 125 / 62 Hz and put through segment_flicks. Overshoot
# came back 0.319 / 0.319 / 0.320 / 0.318 and corrections 2.00 / 2.00 / 2.00 /
# 2.00 — indistinguishable from 1000 Hz all the way down to 125. At 62 Hz both
# break: overshoot 0.349 (+9.4%) and corrections 3.10 (+55%), because a
# corrective submovement lasts ~25-50ms and a 16ms period leaves 2-3 samples
# to see it with.
#
# It was 490 — "below any competitive polling class", which is a judgement
# about hardware tier, not about whether the measurement survives. A 125 Hz
# mouse is the USB default and enormously common, and that threshold withheld
# every overshoot, correction, bias and moment claim on the page from anyone
# using one. All five real runs on this machine were suppressed by it while
# their jitter measured 0.54-0.93ms, which is clean.
POLLING_LOW_HZ = 100.0


def input_degraded(rep) -> bool:
    """True when this run's input timing is too noisy to read flick
    microstructure from — overshoot rates, correction counts, directional
    bias, per-flick moments. Tolerates a missing, empty or None
    `input_health` rather than raising on an old or partial report."""
    health = getattr(rep, "input_health", None) or {}
    jitter = float(health.get("jitter_ms", 0.0) or 0.0)
    polling = float(health.get("polling_hz_est", 0.0) or 0.0)
    return jitter > JITTER_BAD_MS or (0.0 < polling < POLLING_LOW_HZ)


def _clock_epoch(run: Run, hhmmss: str) -> float:
    """A KovaaK's wall-clock timestamp placed on this run's real date."""
    day = datetime(run.started.year, run.started.month, run.started.day)
    h, m, s = hhmmss.split(":")
    value = (day + timedelta(hours=int(h), minutes=int(m),
                             seconds=float(s))).timestamp()
    # The filename timestamp is the challenge END and truncates milliseconds.
    # A clock much later than it belongs to the previous day (midnight run).
    if value > run.started.timestamp() + 5.0:
        value -= 86400.0
    return value


def run_time_window(run: Run) -> tuple[float, float] | None:
    """Epoch (start, end) of the run, reconstructed from the stats file's
    wall-clock kill timestamps.

    run.started (the filename timestamp) is the challenge END, so times are
    anchored to that date; a wall-clock time later in the day than the end
    time happened before midnight and belongs to the previous day
    (midnight-spanning runs)."""
    start_str = run.summary.get("Challenge Start:")
    # A run needs an ANCHOR, not a kill. "Challenge Start:" is one, and the
    # filename timestamp is the challenge END — together they bound the run
    # without a single kill row. Bailing on `not run.kills` threw that away
    # for every invincible-target scenario: nothing dies, so the CSV reports
    # none, and 162 of the 398 real stats files here banked NO telemetry at
    # all. Those are precisely the tracking scenarios whose flick data is
    # worth having, and the recording was being discarded seconds after it
    # was made.
    if not run.kills and not start_str:
        return None
    end_epoch = run.started.timestamp()

    if start_str:
        t0 = _clock_epoch(run, start_str)
    else:
        # Older stats files lack "Challenge Start:" — reconstruct from the
        # first kill (its TTK covers the time since that target appeared).
        t0 = _clock_epoch(run, run.kills[0].timestamp) \
            - max(run.kills[0].ttk, 0.0) - 1.0
    # With kills, the last one plus follow-through; without, the challenge
    # end from the filename, which is what run.started already is.
    t1 = (_clock_epoch(run, run.kills[-1].timestamp) + 2.0) \
        if run.kills else end_epoch
    if t1 < t0:  # crossed midnight
        t1 += 86400.0
    return t0, t1


def one_shot_outcomes(run: Run, trace: MouseTrace,
                      tolerance: float = 0.120) -> list[dict]:
    """Link one-hit KovaaK's acquisitions to Raw Input click timestamps.

    Each per-kill CSV row states how many shots were used to acquire that
    target and the wall-clock time of the killing hit.  For rows with exactly
    one hit, the click nearest that timestamp is the hit and the immediately
    preceding ``shots - 1`` clicks are misses.  Multi-hit targets are skipped:
    their row does not expose which earlier clicks dealt damage, and guessing
    would turn tracking/switching data into false static-click labels.
    """
    clicks = np.asarray(trace.clicks, dtype=np.float64)
    if clicks.size == 0 or not run.kills:
        return []
    labeled: dict[int, bool] = {}
    previous_hit = -1
    for kill in run.kills:
        if kill.hits != 1 or kill.shots < 1:
            continue
        event_t = _clock_epoch(run, kill.timestamp)
        at = int(np.searchsorted(clicks, event_t))
        candidates = [i for i in (at - 1, at) if previous_hit < i < clicks.size]
        if not candidates:
            continue
        hit_i = min(candidates, key=lambda i: abs(float(clicks[i]) - event_t))
        if abs(float(clicks[hit_i]) - event_t) > tolerance:
            continue
        first_i = hit_i - kill.shots + 1
        if first_i <= previous_hit or first_i < 0:
            continue
        for i in range(first_i, hit_i):
            labeled[i] = False
        labeled[hit_i] = True
        previous_hit = hit_i
    return [{"t_click": float(clicks[i]), "hit": hit}
            for i, hit in sorted(labeled.items())]


@dataclass
class RunReport:
    scenario: str
    started_iso: str
    # stats-derived
    score: float
    accuracy: float
    avg_ttk: float
    kills: int
    kps: float
    # telemetry-derived (empty/zero when no trace was captured)
    n_flicks: int = 0
    # The flick-amplitude floor `n_flicks`, `bias` and everything else derived
    # from segmentation were measured at, in DEGREES. Reports are the app's
    # long-lived evidence — the Changes ledger pools bias across every one on
    # disk — so a change to what counts as a flick makes the older files a
    # different population, not a longer run of the same one. 0.0 means
    # "written before this field existed", i.e. the 0.33-degree floor.
    flick_floor_deg: float = 0.0
    #: Degrees of view turn per mouse count for THIS run, read out of the
    #: game's own record of the sensitivity it was played at. 0.0 means the
    #: scale could not be resolved, so nothing derived from it may be stated
    #: as an angle. Stored per run because it MOVES: the 398 stats files here
    #: span five sensitivities and three DPI settings, so one count is a
    #: different angle in different runs and pooling them without this is the
    #: same mistake as pooling across flick floors.
    deg_per_count: float = 0.0
    mouse_dpi: float = 0.0
    #: The scenario's PLAYER_FRAME (scenario/capability.py) for this run.
    #: MOBILE means the player could strafe, and every flick statistic here
    #: was integrated in a frame that was itself moving — overshoot becomes
    #: compensation error and directional bias is confounded by strafe
    #: direction. Recorded per run because it is a property of the scenario
    #: the run was played on, and because a report read a year from now must
    #: still know whether its own microstructure meant anything.
    #: "" means nobody looked; it is not a claim of stillness.
    player_frame: str = ""
    bias: dict = field(default_factory=dict)
    region_deficits: dict = field(default_factory=dict)
    notable: list[dict] = field(default_factory=list)
    total_travel_counts: float = 0.0
    mean_flick_ms: float = 0.0
    overshoot_rate: float = 0.0
    mean_corrections: float = 0.0    # corrective submovements per flick
    fitts_slope_ms: float = 0.0      # ms of flick time per bit of distance (0 = not enough flicks)
    summary_text: str = ""
    trace_file: str = ""
    clip_files: dict = field(default_factory=dict)   # notable idx -> mp4 path
    fatigue: dict = field(default_factory=dict)      # session FatigueState snapshot
    input_health: dict = field(default_factory=dict)  # polling/jitter/click-hold
    # Per-click outcomes inferred only from one-hit acquisition rows. Keeping
    # the Raw Input timestamps lets a saved report reapply them when its trace
    # is re-segmented under a newer flick-amplitude floor.
    shot_outcomes: list[dict] = field(default_factory=list)
    click_phases: dict = field(default_factory=dict)
    # Neural flick-score digest (ml/infer.py:summarize), stamped by the
    # watcher when a trained checkpoint exists. analysis/ itself never
    # imports kovadapt.ml — it stays a pure leaf; ml is built ON analysis.
    ml: dict = field(default_factory=dict)

    def save(self, path: Path | str) -> Path:
        path = Path(path)
        path.parent.mkdir(parents=True, exist_ok=True)
        path.write_text(json.dumps(asdict(self), indent=2))
        return path

    @classmethod
    def load(cls, path: Path | str) -> "RunReport":
        return cls(**json.loads(Path(path).read_text()))


def summary_text_for(rep: "RunReport") -> str:
    """The headline this report supports RIGHT NOW.

    `summary_text` is the only string on the Analysis page that is persisted
    rather than derived — every other surface re-evaluates `input_degraded`
    at render time. So the moment a threshold moves, a saved report keeps
    saying what was true when it was written: after POLLING_LOW_HZ went
    490 -> 100, four of the five real reports on this machine still read
    "findings are withheld for this run; run the Optimizer checkup" directly
    above a page showing every one of those findings, and prescribing the
    exact wrong cause the change had just removed.

    A stored sentence about a threshold is a cache of a judgement, and this
    is what invalidates it. Pure function of the report, so it costs nothing
    to re-derive.
    """
    return _summary_text(rep, bool(rep.n_flicks))


def _summary_text(rep: "RunReport", flicks_exist: bool) -> str:
    lines = [f"Accuracy {rep.accuracy:.0%}, {rep.kills} kills at {rep.kps:.2f}/s."]
    if not flicks_exist:
        lines.append("No mouse telemetry for this run — start the recorder for movement analysis.")
        return " ".join(lines)
    # Everything below is flick microstructure, so it answers to the same
    # input-health gate the Coach and the KPI strip use. Ungated, this header
    # printed a confident "40% of flicks overshot — consider a slight sens
    # decrease" directly above a tile reading "noisy-input" and a Coach card
    # saying microstructure diagnoses were suppressed for that very run.
    if input_degraded(rep):
        ih = rep.input_health or {}
        jitter = float(ih.get("jitter_ms", 0.0) or 0.0)
        polling = float(ih.get("polling_hz_est", 0.0) or 0.0)
        # NAME THE ACTUAL CAUSE. These two have different causes and
        # different fixes, and the message gave one answer for both: it told
        # a 125 Hz mouse to go check for background apps. Jitter IS
        # contention — something is delaying packets that did arrive. A low
        # report rate is a device or driver setting, and no amount of closing
        # Chrome will change it.
        # BOTH, when both are wrong. Branching on jitter alone meant a device
        # that was slow AND contended got told only about the contention, and
        # the user fixed one thing and wondered why nothing changed.
        if jitter > JITTER_BAD_MS and 0.0 < polling < POLLING_LOW_HZ:
            lines.append(
                f"Two things are stopping flick microstructure being read this "
                f"run: your mouse reports at about {polling:.0f}Hz, under the "
                f"{POLLING_LOW_HZ:.0f}Hz needed to see corrective submovements, "
                f"and packets are arriving {jitter:.1f}ms apart when they do. "
                "The first is a device or driver setting; the second is "
                "something on the system delaying input. Both need fixing.")
        elif jitter > JITTER_BAD_MS:
            lines.append(
                f"Input timing is too noisy to read flick microstructure from "
                f"(jitter {jitter:.1f}ms between packets) — overshoot and bias "
                "findings are withheld for this run; something is delaying "
                "mouse input, so run the Optimizer checkup for background "
                "apps or USB contention.")
        else:
            lines.append(
                f"Your mouse is reporting at about {polling:.0f}Hz, which is "
                f"under the {POLLING_LOW_HZ:.0f}Hz this analysis needs to see "
                "individual corrective submovements — overshoot and bias "
                "findings are withheld for this run. This is a device or "
                "driver setting, not background load: raise the polling rate "
                "in your mouse software.")
        if rep.mean_flick_ms > 0:
            lines.append(f"Mean flick {rep.mean_flick_ms:.0f}ms.")
        return " ".join(lines)
    b = rep.bias.get("bias_score", 0.0)
    if abs(b) > 0.15:
        weak = "left" if b > 0 else "right"
        lines.append(
            f"Your {weak} side is measurably weaker "
            f"({rep.bias[weak]['overshoot']:.0%} overshoot vs "
            f"{rep.bias['right' if weak == 'left' else 'left']['overshoot']:.0%})."
        )
        # NO forward-looking clause. This said "spawns will shift {weak}" and
        # was wrong twice. Wrong mechanism: nothing about spawns moves — a
        # directional bias writes Left/RightStrafeTimeMult. And wrong side:
        # this function has only the REPORT, so it read THIS run's
        # bias_score, while engine.py acts on profile.ewma_bias behind a 0.05
        # gate. Replayed over the five real runs here, two printed "shift
        # left" while the engine wrote right skew and the What-changed page
        # agreed with the engine.
        #
        # A report describes a run. What the engine does next depends on
        # profile state a report does not carry, and the Adaptability page
        # already says it — from the profile, with the gate applied.
    else:
        lines.append("Left/right flicks are balanced this run.")
    if rep.overshoot_rate > 0.25:
        lines.append(f"{rep.overshoot_rate:.0%} of flicks overshot — consider a slight sens decrease or larger targets; the engine will compensate.")
    if rep.mean_flick_ms > 0:
        lines.append(f"Mean flick {rep.mean_flick_ms:.0f}ms.")
    phases = rep.click_phases or {}
    labeled = int(phases.get("labeled", 0) or 0)
    if labeled:
        misses = int(phases.get("misses", 0) or 0)
        raw_misses = int(phases.get("uncorrected_misses", 0) or 0)
        direct = int(phases.get("direct_hits", 0) or 0)
        lines.append(
            f"Matched {labeled} clicks to one-hit target outcomes: {misses} "
            f"misses, {direct} hits without a detectable correction, and "
            f"{raw_misses} misses fired without one.")
    ih = rep.input_health or {}
    # `or 0.0`: a report carrying a null polling value used to raise TypeError
    # here rather than simply skipping the note.
    polling = float(ih.get("polling_hz_est", 0.0) or 0.0)
    # the CONSTANT, not a literal 125. When the gate moved to 100 this left a
    # dead band at [100, 125): a rate the analysis now trusts and never
    # mentioned, so the reader had no way to know it was borderline.
    if polling >= POLLING_LOW_HZ:
        note = f"Mouse polling ~{polling:.0f}Hz"
        if float(ih.get("jitter_ms", 0.0) or 0.0) > 1.0:
            note += (f", timing jitter {float(ih['jitter_ms']):.1f}ms — high; run "
                     "the Optimizer checkup (background apps or USB contention)")
        lines.append(note + ".")
    return " ".join(lines)


def apply_flick_metrics(rep: "RunReport", flicks: list, *,
                        cols: int = 3, rows: int = 3) -> "RunReport":
    """Write every field derived from a flick SET onto `rep`, in place.

    Split out of build_report because the Analysis page needs the same
    derivation without the stats Run: a saved report segmented at a different
    flick floor has to be re-derived from its trace before it is rendered, and
    two copies of this arithmetic is two chances for the page and the file to
    disagree about the same run.

    Fields NOT here are the ones a floor change cannot move —
    total_travel_counts and input_health come from the packet stream, not from
    what was called a flick.
    """
    rep.n_flicks = len(flicks)
    rep.bias = directional_bias(flicks)
    rep.region_deficits = region_deficits(flicks, cols=cols, rows=rows)
    rep.notable = [asdict(m) for m in find_notable_moments(flicks)]
    rep.click_phases = click_phase_metrics(flicks)
    # Reset rather than leave stale: re-deriving a report with FEWER flicks
    # must not keep the old mean beside the new count.
    rep.mean_flick_ms = rep.overshoot_rate = rep.mean_corrections = 0.0
    rep.fitts_slope_ms = 0.0
    if flicks:
        rep.mean_flick_ms = float(np.mean([f.duration for f in flicks]) * 1000)
        rep.overshoot_rate = float(np.mean([f.overshoot > 0.1 for f in flicks]))
        rep.mean_corrections = float(np.mean([f.corrections for f in flicks]))
        # Within-run Fitts fit: movement time vs log2 distance. The slope
        # (ms/bit) falling across sessions is motor improvement even when
        # scores plateau (see analysis/insights.py: dx-fitts-progress).
        amps = np.array([f.amplitude for f in flicks], dtype=np.float64)
        durs = np.array([f.duration for f in flicks], dtype=np.float64) * 1000.0
        ok = amps > 1.0
        if int(ok.sum()) >= 8:
            x = np.log2(1.0 + amps[ok])
            rep.fitts_slope_ms = float(np.polyfit(x, durs[ok], 1)[0])
    return rep


def build_report(
    run: Run,
    trace: MouseTrace | None,
    *,
    region_cols: int = 3,
    region_rows: int = 3,
    min_amplitude: float | None = None,
    flick_floor_deg: float | None = None,
) -> tuple[RunReport, list, np.ndarray | None]:
    """-> (report, flicks, heatmap). Flicks/heatmap returned separately for
    the GUI (not serialized into JSON).

    region_cols/region_rows must match Settings.region_cols/region_rows so
    the report's region_deficits keys line up with the bandit's region grid
    (the r{row}c{col} cross-module contract); defaults preserve the 3x3
    behavior for callers without Settings.

    min_amplitude is in mouse COUNTS and flick_floor_deg is the ANGLE it was
    converted from. A caller that converts (sens.min_flick_counts) passes
    both; they are stored together in the report so a later reader can tell
    two runs at different sensitivities apart from two runs measured by
    different rules."""
    rep = RunReport(
        scenario=run.scenario,
        started_iso=run.started.isoformat(),
        score=run.score,
        accuracy=run.accuracy,
        avg_ttk=run.avg_ttk,
        kills=run.kill_count,
        kps=run.kills_per_second(),
    )
    # The run's own sensitivity, from the game's record of it. Read before
    # anything is segmented, because it decides what the floor MEANS.
    from .sens import deg_per_count as _deg_per_count
    rep.deg_per_count = _deg_per_count(run)[0]
    try:
        rep.mouse_dpi = float(run.summary.get("DPI:", 0) or 0)
    except (TypeError, ValueError):
        rep.mouse_dpi = 0.0

    flicks: list = []
    heat = None
    if trace is not None and len(trace) > 10:
        win = run_time_window(run)
        rt = trace.window(*win) if win else trace
        # One shared resample for every analysis pass: segment_flicks bins the
        # packets once (500 Hz); movement_heatmap's 250 Hz grid is then derived
        # from that cache instead of re-binning the whole packet stream.
        grid = ResampleCache(rt)
        # The flick floor is an ANGLE, and the angle a count is worth depends
        # on in-game sens — so the caller converts (sens.min_flick_counts) and
        # every surface that segments the same run has to be given the same
        # number, or the page and the profile disagree about what a flick is.
        # Default the floor from the run itself rather than the sens-1.0
        # reference: the caller may still override, but a caller that passes
        # nothing now gets the right answer instead of a plausible one.
        if min_amplitude is None and rep.deg_per_count > 0:
            min_amplitude = MIN_FLICK_DEG / rep.deg_per_count
            flick_floor_deg = MIN_FLICK_DEG
        flicks = segment_flicks(rt, grid=grid, **(
            {} if min_amplitude is None else {"min_amplitude": min_amplitude}))
        rep.shot_outcomes = one_shot_outcomes(run, rt)
        apply_shot_outcomes(flicks, rep.shot_outcomes)
        # The angle cannot be recovered from the count here: the caller divided
        # by the player's sens to get it, and this function is not given sens.
        # So the caller that converted states what it converted FROM, and a
        # caller passing raw counts is taken at the sens-1.0 reference — which
        # is the only reading a bare count has.
        rep.flick_floor_deg = (
            flick_floor_deg if flick_floor_deg is not None
            else MIN_FLICK_DEG if min_amplitude is None
            else min_amplitude * YAW_DEG_PER_COUNT)
        apply_flick_metrics(rep, flicks, cols=region_cols, rows=region_rows)
        rep.total_travel_counts = float(np.hypot(rt.dx.astype(np.float64), rt.dy.astype(np.float64)).sum())
        rep.input_health = rt.input_health()
        heat, _, _ = movement_heatmap(rt, grid=grid)
    rep.summary_text = _summary_text(rep, bool(flicks))
    return rep, flicks, heat
