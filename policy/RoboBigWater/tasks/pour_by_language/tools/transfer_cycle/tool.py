"""A side grasp, compensated tilt, and return using only caller geometry and TCP state."""
import math
import importlib.util
from pathlib import Path
import numpy as np


# Sustained exposure is separate from the endpoint settling allowance.
DEFAULT_DWELL = .80
MIN_DWELL = .80


_home_spec = importlib.util.spec_from_file_location(
    "transfer_joint_return", Path(__file__).parents[1] / "joint_return/tool.py")
_home = importlib.util.module_from_spec(_home_spec)
_home_spec.loader.exec_module(_home)

_axis_spec = importlib.util.spec_from_file_location(
    "transfer_axis_fit", Path(__file__).parents[1] / "axis_fit/tool.py")
_axis = importlib.util.module_from_spec(_axis_spec)
_axis_spec.loader.exec_module(_axis)


class ReservedAPI:
    """Expose public primitives while withholding caller-reserved time."""
    def __init__(self, api, reserve):
        self.api, self.reserve = api, reserve

    def sim_time_left(self):
        return max(0., self.api.sim_time_left() - self.reserve)

    def __getattr__(self, name):
        return getattr(self.api, name)


def scalar(name, default=None, required=False):
    spec = {"name": name, "type": "float"}
    if required:
        spec["required"] = True
    else:
        spec["default"] = default
    return spec


TOOL = {"name": "transfer_cycle", "commands": [{
    "name": "transfer-cycle", "budget": True,
    "help": "side grasp, lift, aim a tip, tilt, return, release and retreat",
    "args": [{"name": "arm", "positional": True, "choices": ["left", "right"]}]
    + [scalar(n, required=True) for n in ("x", "y", "z", "tx", "ty", "tz", "tip")]
    + [scalar("pitch", 120), scalar("clearance", 0.06), scalar("dwell", DEFAULT_DWELL),
       scalar("travel_pitch", 0), scalar("entry_offset", 0.0), scalar("reserve", 0),
       scalar("release_wait", 0.16), scalar("finish_home", 0)],
}]}
TOOL["commands"].append(dict(TOOL["commands"][0], name="transfer-estimate", budget=False,
                            help="validate geometry and report a heuristic motion duration without moving"))


def geometry(a):
    """The held tip starts tip metres vertically above the grasp centre."""
    values = {n: float(a[n]) for n in
              ("x", "y", "z", "tx", "ty", "tz", "tip", "pitch", "clearance", "dwell")}
    if not all(math.isfinite(v) for v in values.values()):
        raise ValueError("all geometry must be finite")
    if not 0.02 <= values["tip"] <= 0.3:
        raise ValueError("tip must be 0.02..0.3 m")
    # A nearly horizontal endpoint with no dwell is not an equivalent shorter
    # version of this operation. Keep a meaningful inversion and exposure even
    # when the caller is trying to fit a tight time budget.
    if not 120 <= abs(values["pitch"]) <= 140:
        raise ValueError("absolute pitch must be 120..140 degrees; shallow inversion is unsupported")
    if not 0.06 <= values["clearance"] <= 0.25 or not MIN_DWELL <= values["dwell"] <= 2:
        raise ValueError("clearance must be 0.06..0.25 m and dwell 0.80..2 s")
    theta = math.radians(values["pitch"])
    c, s = math.cos(theta), math.sin(theta)
    rotation = np.array([[c, 0, s], [0, 1, 0], [-s, 0, c]])
    source = np.array([values[n] for n in ("x", "y", "z")])
    tip_target = np.array([values[n] for n in ("tx", "ty", "tz")])
    pivot = tip_target - rotation @ np.array([0., 0., values["tip"]])
    height = source[2] + values["clearance"]
    above = source.copy()
    above[2] = height
    # Reject unreachable geometry before any movement rather than accept clipping.
    for p in (source, above, pivot):
        if not (-0.75 <= p[0] <= 0.75 and -0.75 <= p[1] <= 0.6 and 0.74 <= p[2] <= 1.45):
            raise ValueError("requested geometry exceeds the TCP workspace")
    if pivot[2] < source[2] + 0.02:
        raise ValueError("target TCP must be at least 0.02 m above the grasp centre")
    return values, source, above, pivot, rotation



def compensated_angles(length, pitch):
    """Partition sin(theta) by its actual chord error, keeping horizontal.

    On [0, 140 degrees], sin is concave and cos is monotone. The maximum
    chord gap is therefore at acos(chord slope), not necessarily the midpoint.
    The mirrored and reversed arcs have the same absolute error.
    """
    angles = [0.]
    for boundary in (math.pi / 2, math.radians(abs(pitch))):
        while angles[-1] < boundary - 1e-12:
            lower = angles[-1]

            def error(upper):
                slope = (math.sin(upper) - math.sin(lower)) / (upper - lower)
                peak = math.acos(max(-1., min(1., slope)))
                return length * (math.sin(peak) - math.sin(lower)
                                 - slope * (peak - lower))

            # Leave numerical margin beneath the public 2.5 mm contract.
            tolerance = .0025 - 1e-10
            upper = boundary
            if error(upper) > tolerance:
                low, high = lower, boundary
                for _ in range(48):
                    middle = (low + high) / 2
                    if error(middle) <= tolerance:
                        low = middle
                    else:
                        high = middle
                # Align nonterminal intervals to whole nominal rotation ticks
                # (90 deg/s at 25 Hz), avoiding a rounding tick at every stop.
                # Rounding downward only reduces the concave chord error.
                quantum = math.radians(90 / 25)
                upper = lower + math.floor((low - lower) / quantum) * quantum
                if upper <= lower:
                    upper = low
            angles.append(upper)
    return [math.degrees(angle) for angle in angles]


def motion_steps(previous, pos, rot):
    """Cartesian timing heuristic, NOT a bound on joint-retimed motion.

    Nominal .20 m/s and 90 deg/s are planning estimates, not server limits.
    The server has a one-tick minimum and no fixed settling holds; measured
    joint convergence can still add time. Do not add the retired eight ticks.
    """
    relative = previous[:3, :3].T @ rot
    angle = math.degrees(math.acos(float(np.clip((np.trace(relative)-1)/2, -1, 1))))
    distance = np.linalg.norm((pos - .145 * rot[:, 0]) -
                              (previous[:3, 3] - .145 * previous[:3, 0]))
    return max(1, math.ceil(max(distance/.20, angle/90) * 25 - 1e-9))


def endpoint_error(pose, pos, rot):
    pose = np.asarray(pose, dtype=float)
    if pose.shape != (4, 4) or not np.isfinite(pose).all():
        raise RuntimeError("invalid measured TCP")
    position = float(np.linalg.norm(pose[:3, 3] - pos))
    angle = math.degrees(math.acos(float(np.clip(
        (np.trace(pose[:3, :3].T @ rot) - 1) / 2, -1, 1))))
    return position, angle


def hand_cloud(pose):
    """Sample the TCP-to-wrist segment; 0.10 m separation includes sampling margin."""
    pose = np.asarray(pose, dtype=float)
    if pose.shape != (4, 4) or not np.isfinite(pose).all():
        raise ValueError("invalid measured hand pose")
    return pose[:3, 3] - np.linspace(0, .145, 16)[:, None] * pose[:3, 0]


def inactive_retreat(start, path, other_pose):
    # This is a local hand-envelope guard, not full robot or scene collision checking.
    clouds = [hand_cloud(start)]
    previous = start.copy()
    for _, pos, rot in path:
        target = np.eye(4)
        target[:3, 3], target[:3, :3] = pos, rot
        first, last = hand_cloud(previous), hand_cloud(target)
        count = max(2, math.ceil(float(np.max(np.linalg.norm(last-first, axis=1))) / .01) + 1)
        clouds.extend((1-t)*first + t*last for t in np.linspace(0, 1, count))
        previous = target
    swept = np.concatenate(clouds)
    def clear(pose):
        delta = swept[:, None, :] - hand_cloud(pose)[None, :, :]
        return float(np.min(np.sum(delta*delta, axis=2))) >= .10**2
    if clear(other_pose):
        return None
    # Retract along the current approach axis, preserving orientation/altitude
    # for the usual horizontal side grasp. Never sweep sideways through the row.
    for distance in np.arange(.04, .401, .02):
        candidate = other_pose.copy()
        candidate[:3, 3] -= distance * other_pose[:3, 0]
        x, y, z = candidate[:3, 3]
        if not (-.75 <= x <= .75 and -.75 <= y <= .6 and .74 <= z <= 1.45):
            continue
        if clear(candidate):
            moving = np.concatenate([hand_cloud(other_pose) - t * distance * other_pose[:3, 0]
                                     for t in np.linspace(0, 1, math.ceil(distance/.01)+1)])
            delta = moving[:, None, :] - hand_cloud(start)[None, :, :]
            if float(np.min(np.sum(delta*delta, axis=2))) < .10**2:
                continue
            return candidate
    raise ValueError("inactive hand obstructs path; no bounded retraction available")


def run(api, command, args):
    stages = []
    active = "validate"
    try:
        if command not in ("transfer-cycle", "transfer-estimate") or args.get("arm") not in ("left", "right"):
            raise ValueError("invalid command or arm")
        finish_home = float(args.get("finish_home", 0))
        if finish_home not in (0., 1.):
            raise ValueError("finish_home must be 0 or 1")
        if finish_home:
            _home.home_status(api, ("left", "right"))
            if any(api.arm(tag).gripper() < .9 for tag in ("left", "right")):
                raise ValueError("finish_home requires both hands initially open and inactive hand empty")
        a = dict(args)
        for key, default in (("pitch", 120), ("clearance", 0.06), ("dwell", DEFAULT_DWELL),
                             ("travel_pitch", 0), ("entry_offset", 0.0), ("reserve", 0),
                             ("release_wait", 0.16)):
            a.setdefault(key, default)
        release_wait = float(a["release_wait"])
        if not math.isfinite(release_wait) or not 0.16 <= release_wait <= 0.48:
            raise ValueError("release_wait must be 0.16..0.48 s")
        release_steps = math.ceil(release_wait * 25)
        reserve = float(a["reserve"])
        if not math.isfinite(reserve) or reserve < 0:
            raise ValueError("reserve must be finite and nonnegative")
        values, source, above, pivot, tilt = geometry(a)
        travel_pitch = float(a["travel_pitch"])
        if not math.isfinite(travel_pitch) or travel_pitch != 0:
            raise ValueError("travel_pitch must be 0 degrees; loaded transport must stay upright")
        support = _axis.grasp_support(api.observe(), source, values['tip'])
        if support.get('supported') is False:
            return {"plan_ok": False, "plan_fail_reason": "narrow_grasp_section",
                    "plan_detail": "Selected section is over 1.5 times narrower than a measured lower section; "
                                   "suggested_geometry preserves the supplied standing tip height.",
                    "grasp_support": support, "stages": []}, 2
        entry_offset = float(a["entry_offset"])
        if not math.isfinite(entry_offset) or not (entry_offset == 0 or 0.08 <= entry_offset <= 0.25):
            raise ValueError("entry_offset must be 0 or 0.08..0.25 m")
        arm = api.arm(a["arm"])
        if arm.gripper() < 0.9:
            raise ValueError("requires an open gripper")
        start = arm.tcp().copy()
        # Empty fingers must clear the entire standing item, not just its grasp.
        # Preserve the current altitude when the caller reduces clearance between
        # cycles; otherwise the approach becomes a descending lateral sweep.
        empty_above = above.copy()
        empty_above[2] = max(above[2], source[2] + values["tip"] + 0.04, start[2, 3])
        if empty_above[2] > 1.45:
            raise ValueError("tip clearance exceeds the TCP workspace")
        # Keep every loaded crossing upright. A tilted crossing can shed
        # contents before reaching (or after leaving) the compensated arc.
        travel_tilt = np.eye(3)
        # Align the tip at each angular endpoint, including before horizontal.
        # Preserve source lift altitude while upright and through horizontal.
        # Using the final inverted TCP height here can lower the held base
        # into destination geometry before rotation even starts. Blend down
        # only after horizontal; reverse this path before upright departure.
        # A small rotation margin also accommodates the downward sweep of
        # off-axis surfaces; this is not a full held-shape collision model.
        arc_height = max(above[2] + .02, pivot[2])
        if arc_height > 1.45:
            raise ValueError("rotation clearance exceeds the TCP workspace")
        # Retention below horizontal is not measured. Bound interpolation
        # drift throughout the arc, including the early tilt and late recovery.
        # Use the exact sine chord maximum instead of worst-case curvature
        # everywhere; fewer early stops retain the same 2.5 mm contract.
        angles = compensated_angles(values["tip"], values["pitch"])
        arc = []
        for angle in angles:
            radians = math.radians(math.copysign(angle, values["pitch"]))
            c, s = math.cos(radians), math.sin(radians)
            rotation = np.array([[c, 0., s], [0., 1., 0.], [-s, 0., c]])
            position = pivot.copy()
            position[0] = values["tx"] - values["tip"] * s
            descent = max(0., (angle - 90.) / (abs(values["pitch"]) - 90.))
            position[2] = arc_height + descent * (pivot[2] - arc_height)
            if not -.75 <= position[0] <= .75:
                raise ValueError("intermediate tip compensation exceeds the TCP workspace")
            arc.append((position, rotation))
        aim = arc[0][0]
        # Side approach +Y, opening along X; choose the nearer symmetric frame.
        forward = np.array([0., 1., 0.])
        across = np.array([-1., 0., 0.])
        upright = np.column_stack((forward, across, np.cross(forward, across)))
        if np.dot(start[:3, 1], across) < 0:
            upright[:, 1:] *= -1

        # Compile the complete path before acting. A positive offset requests a
        # caller-certified free front corridor, avoiding repeated tip-height
        # climbs. Never cross sideways while still in the standing-item row.
        path = []
        def waypoint(name, pos, rot):
            path.append((name, np.asarray(pos).copy(), np.asarray(rot).copy()))

        if entry_offset:
            entry = above - np.array([0., entry_offset, 0.])
            if entry[1] < -0.75:
                raise ValueError("entry corridor exceeds the TCP workspace")
            if start[1, 3] > entry[1] + 0.001:
                back = start[:3, 3].copy()
                back[1] = entry[1]
                waypoint("back_out", back, start[:3, :3])
            waypoint("approach", entry, upright)
            # Align at grasp height outside the item before insertion. A
            # diagonal descent can touch an upper section before reaching the
            # intended grasp section, even with an accurate final TCP.
            front = source - np.array([0., entry_offset, 0.])
            waypoint("align_front", front, upright)
            waypoint("advance", source, upright)
            retreat = entry
        else:
            if start[2, 3] < empty_above[2] - 0.001:
                raised = start[:3, 3].copy()
                raised[2] = empty_above[2]
                waypoint("raise_empty", raised, start[:3, :3])
            waypoint("approach", empty_above, upright)
            waypoint("descend", source, upright)
            retreat = empty_above
        waypoint("lift", above, upright)
        if entry_offset:
            # Keep the held item upright until it has left the pickup row.
            # A diagonal rotating departure can sweep its lower body through
            # neighbours even when the TCP endpoints are unobstructed.
            waypoint("exit_loaded", entry, upright)
        waypoint("aim", aim, travel_tilt @ upright)
        for i, (position, rotation) in enumerate(arc[1:], 1):
            name = "tilt" if i == len(arc)-1 else f"tilt_segment_{i}"
            waypoint(name, position, rotation @ upright)
        # Reverse the same compensated arc before any loaded return travel.
        recovery_pitch = travel_pitch
        for i in range(len(arc)-2, -1, -1):
            position, rotation = arc[i]
            name = "untilt" if i == 0 else f"recover_segment_{i}"
            waypoint(name, position, rotation @ upright)
        if entry_offset:
            # Complete the lateral return and uprighting in the same caller-
            # certified front corridor before reinserting into the row.
            waypoint("return_front", entry, upright)
        waypoint("return_above", above, upright)
        # Decelerate before the support surface. A single full-clearance
        # descent can encounter contact before its endpoint, while still
        # moving quickly. A separate final centimetre limits the remaining
        # travel from rest without weakening the measured release check.
        preplace = source + np.array([0., 0., .01])
        waypoint("preplace", preplace, upright)
        waypoint("replace", source, upright)
        if finish_home:
            # Joint-space homing can initially sweep sideways while the open
            # fingers still surround the released item. Withdraw along the
            # caller's insertion corridor with fixed orientation first.
            withdrawal = source - np.array([0., entry_offset, 0.]) if entry_offset else retreat
            waypoint("withdraw", withdrawal, upright)
        else:
            if entry_offset:
                # Clear the released item at fixed height before rising;
                # opening feedback does not establish finger clearance.
                waypoint("withdraw", front, upright)
            waypoint("retreat", retreat, upright)

        other_tag = "right" if a["arm"] == "left" else "left"
        other = api.arm(other_tag)
        other_start = other.tcp().copy()
        parking = inactive_retreat(start, path, other_start)
        if parking is not None and other.gripper() < .9:
            raise ValueError("inactive hand obstructs path and is not open")
        parking_steps = (0 if parking is None else
                         motion_steps(other_start, parking[:3, 3], parking[:3, :3]))
        parking_info = {"arm": other_tag, "required": parking is not None,
                        "estimated_seconds": parking_steps / 25,
                        "target": None if parking is None else parking[:3, 3].tolist()}

        # Nominal Cartesian heuristic plus the default eight-tick close.
        # Actual joint retiming and adaptive settling may be faster or slower.
        estimated_steps = parking_steps + 8 + release_steps + math.ceil(values["dwell"] * 25)
        previous = start.copy()
        for _, pos, rot in path:
            estimated_steps += motion_steps(previous, pos, rot)
            previous[:3, 3], previous[:3, :3] = pos, rot
        estimated_seconds = estimated_steps / 25
        if command == "transfer-estimate":
            return {"plan_ok": True, "plan_fail_reason": None, "estimated_seconds": estimated_seconds,
                    "grasp_support": support,
                    "time_left_seconds": api.sim_time_left(), "joint_retiming_unaccounted": True,
                    "timing_warning": "heuristic only, not a lower bound or deadline guarantee; actual joint retiming and settling may take more or less time",
                    "reachability_checked": False, "reserve_seconds": reserve,
                    "finish_home": bool(finish_home),
                    "home_time_unaccounted": bool(finish_home),
                    "inactive_retreat": parking_info,
                    "release_wait_seconds": release_steps / 25,
                    "estimate_with_reserve_seconds": estimated_seconds + reserve,
                    "fits_estimate": estimated_seconds + reserve <= api.sim_time_left(),
                    "waypoints": [{"stage": n, "pos": p.tolist()} for n, p, _ in path]}, 0
        if estimated_seconds + reserve > api.sim_time_left():
            return {"plan_ok": False, "plan_fail_reason": "insufficient_time",
                    "estimated_seconds": estimated_seconds, "reserve_seconds": reserve, "stages": []}, 2

        split_aim = False
        tilt_hold_steps = 0
        def move(name, pos, rot, allow_split=False, remaining_steps=0):
            nonlocal active
            nonlocal split_aim
            active = name
            if api.over:
                raise RuntimeError("episode ended")
            target = np.eye(4)
            target[:3, :3], target[:3, 3] = rot, pos
            feedback = {}
            before = arm.tcp().copy()
            time_before = api.sim_time_left()
            code = api.move_tcp(arm, target, feedback)
            stages.append(dict(feedback, stage=name))
            # A base IK failure executes no steps. Change the path only once,
            # never retry tracking errors, clipping, or a partially executed move.
            if (allow_split and code and feedback.get("plan_fail_reason") == "ik_unreachable"
                    and not feedback.get("workspace_limited") and not api.over
                    and abs(api.sim_time_left() - time_before) < 1e-9
                    and np.allclose(arm.tcp(), before, atol=1e-6, rtol=0)):
                turned = before.copy()
                turned[:3, :3] = rot
                required = (motion_steps(before, before[:3, 3], rot)
                            + motion_steps(turned, pos, rot) + remaining_steps) / 25 + reserve
                if required > api.sim_time_left():
                    raise RuntimeError("insufficient_time_for_split_aim")
                move("aim_rotate", before[:3, 3], rot)
                move("aim_translate", pos, rot)
                split_aim = True
                return
            if code or not feedback.get("plan_ok") or api.over:
                raise RuntimeError(feedback.get("plan_fail_reason") or "episode ended")
            if feedback.get("workspace_limited") or feedback.get("error_m", 0) > 0.015 or feedback.get("error_deg", 0) > 5:
                raise RuntimeError("target was clipped or not reached accurately")

        def grip(name, value):
            nonlocal active
            active = name
            if api.over or api.set_gripper(arm, value) is False or api.over:
                raise RuntimeError("episode ended")

        def release():
            nonlocal active
            active = "release"
            if api.over:
                raise RuntimeError("episode ended")
            # Replacement has already reached and settled at the support pose.
            # Allow an initial opening interval before retreat; the open target
            # remains active for the entire retreat. Closing retains the full
            # base hold. This is commanded aperture, not measured clearance.
            arm.gripper_target = 1.0
            if api.hold(release_steps) is False or api.over:
                raise RuntimeError("episode ended")

        if parking is not None:
            active = "clear_inactive"
            feedback = {}
            if api.over:
                raise RuntimeError("episode ended")
            code = api.move_tcp(other, parking, feedback)
            stages.append(dict(feedback, stage=active, arm=other_tag))
            error_m, error_deg = endpoint_error(other.tcp(), parking[:3, 3], parking[:3, :3])
            if (code or not feedback.get("plan_ok") or feedback.get("workspace_limited")
                    or api.over or error_m > .01 or error_deg > 1):
                raise RuntimeError("inactive retraction failed")

        for name, pos, rot in path:
            if name == "withdraw":
                active = name
                needed = motion_steps(arm.tcp(), pos, rot) / 25 + reserve
                if needed >= api.sim_time_left():
                    raise RuntimeError("insufficient_time_for_withdrawal")
            remaining_steps = 0
            if name == "aim":
                previous = np.eye(4)
                previous[:3, 3], previous[:3, :3] = pos, rot
                # Remaining release, dwell and motion; closing already finished.
                remaining_steps = release_steps + math.ceil(values["dwell"] * 25)
                after_aim = False
                for later, p, r in path:
                    if after_aim:
                        remaining_steps += motion_steps(previous, p, r)
                        previous[:3, 3], previous[:3, :3] = p, r
                    after_aim = after_aim or later == "aim"
            move(name, pos, rot, allow_split=name == "aim", remaining_steps=remaining_steps)
            if name.startswith(("tilt_segment_", "recover_segment_")):
                error_m, error_deg = endpoint_error(arm.tcp(), pos, rot)
                accurate = error_m <= .005 and error_deg <= 1.
                stages[-1]["arc_check"] = dict(plan_ok=accurate,
                    error_m=error_m, error_deg=error_deg)
                if not accurate:
                    raise RuntimeError("compensated_arc_not_reached")
            if name == "preplace":
                # Do not start the short descent from an inaccurate staging
                # pose; in particular, a downward tracking error could consume
                # the intended contact margin. No retry or extra hold here.
                error_m, error_deg = endpoint_error(arm.tcp(), pos, rot)
                ready = error_m <= .002 and error_deg <= .5
                stages[-1]["preplace_check"] = dict(
                    plan_ok=ready, error_m=error_m, error_deg=error_deg)
                if not ready:
                    raise RuntimeError("preplacement_not_reached")
            if name == "withdraw":
                measured = arm.tcp()
                error_m, error_deg = endpoint_error(measured, pos, rot)
                target = np.eye(4)
                target[:3, 3], target[:3, :3] = pos, rot
                # This endpoint is an empty-hand clearance check. Bound the
                # entire sampled TCP-to-wrist segment, not only attitude: a
                # small rotation can be harmless after horizontal extraction.
                # Retain the translation limit and reject larger rotations;
                # this neither establishes scene clearance nor permits retries.
                hand_error = float(np.max(np.linalg.norm(
                    hand_cloud(measured) - hand_cloud(target), axis=1)))
                withdrawn = error_m <= .01 and error_deg <= 2. and hand_error <= .015
                stages[-1]["withdrawal_check"] = dict(
                    plan_ok=withdrawn, error_m=error_m, error_deg=error_deg,
                    hand_error_m=hand_error)
                if not withdrawn:
                    raise RuntimeError("withdrawal_not_settled")
            if name == "untilt":
                error_m, error_deg = endpoint_error(arm.tcp(), pos, rot)
                # Recovery is a transport endpoint, not the exposure endpoint.
                # Permit small residual attitude error while bounding its effect
                # on the caller's tip. At nominal <=60 degrees, this still leaves
                # at least 28 degrees before horizontal. No extra motion/hold.
                tip_error_bound = error_m + 2 * values["tip"] * math.sin(math.radians(error_deg) / 2)
                recovered = error_m <= .01 and error_deg <= 2. and tip_error_bound <= .015
                stages[-1]["recovery_check"] = dict(
                    plan_ok=recovered, error_m=error_m, error_deg=error_deg,
                    tip_error_bound_m=tip_error_bound)
                if not recovered:
                    raise RuntimeError("recovery_not_settled")
            if name in ("advance", "descend"):
                grip("close", 0.)
            elif name == "tilt":
                active = "dwell"
                # Exposure counts only while the measured endpoint is accurate.
                # A successful base plan can still report unsettled tracking.
                # Six extra ticks bound recovery. An already stable exposure
                # may finish within three more ticks, without restarting it.
                required = math.ceil(values["dwell"] * 25)
                stable = 0
                downstream = release_steps
                previous = np.eye(4)
                previous[:3, 3], previous[:3, :3] = pos, rot
                after_tilt = False
                for later, p, r in path:
                    if after_tilt:
                        downstream += motion_steps(previous, p, r)
                        previous[:3, 3], previous[:3, :3] = p, r
                    after_tilt = after_tilt or later == "tilt"
                completion_ticks = 0
                for tick in range(required + 9):
                    if tick >= required + 6:
                        if stable == 0 or required - stable > 3:
                            break
                        completion_ticks += 1
                    before_error = endpoint_error(arm.tcp(), pos, rot)
                    accurate_before = before_error[0] <= .01 and before_error[1] <= 1.
                    # Reserve the remaining nominal dwell as well as the return.
                    needed = downstream + max(1, required - stable)
                    if needed + math.ceil(reserve * 25 - 1e-9) > math.floor(api.sim_time_left() * 25 + 1e-9):
                        raise RuntimeError("insufficient_time_for_tilt_settling")
                    if api.over or api.hold(1) is False or api.over:
                        raise RuntimeError("episode ended")
                    tilt_hold_steps += 1
                    error_m, error_deg = endpoint_error(arm.tcp(), pos, rot)
                    accurate_after = error_m <= .01 and error_deg <= 1.
                    stable = stable + 1 if accurate_before and accurate_after else 0
                    if completion_ticks and stable == 0:
                        break
                    if stable >= required:
                        break
                stages[-1]["dwell"] = dict(plan_ok=stable >= required,
                                   plan_fail_reason=None if stable >= required else "tilt_not_settled",
                                   error_m=error_m, error_deg=error_deg,
                                   hold_steps=tilt_hold_steps, stable_steps=stable,
                                   completion_ticks=completion_ticks)
                if stable < required:
                    raise RuntimeError("tilt_not_settled")
            elif name == "replace":
                # A successful Cartesian plan permits substantially more error
                # than a supported release. Check the measured pose while still
                # closed; opening first makes subsequent settling ineffective.
                active = "placement_settle"
                settle_steps = 0
                error_m, error_deg = endpoint_error(arm.tcp(), pos, rot)
                window_error = max(error_m / .002, error_deg / .5)
                progress_windows = []
                downstream = release_steps
                previous = arm.tcp().copy()
                after_replace = False
                for later, p, r in path:
                    if after_replace:
                        downstream += motion_steps(previous, p, r)
                        previous[:3, 3], previous[:3, :3] = p, r
                    after_replace = after_replace or later == "replace"
                while error_m > .002 or error_deg > .5:
                    check = dict(plan_ok=False, error_m=error_m, error_deg=error_deg,
                                 hold_steps=settle_steps, progress_windows=progress_windows)
                    stages[-1]["placement_check"] = check
                    if settle_steps >= 12:
                        raise RuntimeError("placement_not_settled")
                    # Measure progress in the remaining violation, not the
                    # already acceptable part of the pose error. Otherwise a
                    # near-threshold pose must overshoot tolerance to qualify
                    # for another window. Stalled contact still stops closed.
                    if settle_steps and settle_steps % 4 == 0:
                        current_error = max(error_m / .002, error_deg / .5)
                        start_excess = max(0., window_error - 1.)
                        end_excess = max(0., current_error - 1.)
                        improving = end_excess <= .9 * start_excess
                        progress_windows.append(dict(hold_steps=settle_steps,
                            start_error=window_error, end_error=current_error,
                            start_excess=start_excess, end_excess=end_excess,
                            improving=improving))
                        if not improving:
                            raise RuntimeError("placement_not_settled")
                        window_error = current_error
                    needed = downstream + 1 + math.ceil(reserve * 25 - 1e-9)
                    if needed >= math.floor(api.sim_time_left() * 25 + 1e-9):
                        raise RuntimeError("insufficient_time_for_placement_settling")
                    if api.over or api.hold(1) is False or api.over:
                        raise RuntimeError("episode ended")
                    settle_steps += 1
                    error_m, error_deg = endpoint_error(arm.tcp(), pos, rot)
                stages[-1]["placement_check"] = dict(
                    plan_ok=True, error_m=error_m, error_deg=error_deg,
                    hold_steps=settle_steps, progress_windows=progress_windows)
                release()
        home_result = None
        if finish_home:
            active = "finish_home"
            home_result, code = _home.run(ReservedAPI(api, reserve), "joint-return", {"arm": "both"})
            stages.append(dict(home_result, stage=active))
            if code or not home_result.get("joint_return_verified"):
                raise RuntimeError(home_result.get("plan_fail_reason") or "home verification failed")
        # Lead with measured completion, before potentially long stage traces.
        # Use the real clock here: the return planner sees a reserve-subtracted
        # clock, whereas this describes the budget of a subsequent base command.
        completion = {"home_verified": False, "episode_live": not api.over,
                      "scene_completion_verified": False}
        if finish_home:
            status = _home.home_status(api, ("left", "right"))
            followup = status["base_home_followup"]
            completion.update(
                home_verified=bool(home_result["joint_return_verified"] and
                                   status["all_selected_at_home"]),
                home_arm_scope=["left", "right"],
                target_reference=status["target_reference"],
                remaining_steps=followup["available_steps"],
                repeated_home_required_steps=followup["required_steps"],
                repeated_home_fits=followup["fits_with_live_episode"],
                message="Both arms already reached the base home joint targets. " +
                        ("Another home repeats the completed movement." if followup["fits_with_live_episode"] else
                         "Another home would exhaust the remaining episode time."))
        return {"plan_ok": True, "plan_fail_reason": None, "completion": completion,
                "grasp_support": support,
                "finish_home": bool(finish_home), "home_result": home_result,
                "tip_target": [values[n] for n in ("tx", "ty", "tz")],
                "empty_travel_z": float(empty_above[2]), "travel_pitch": travel_pitch, "recovery_pitch": recovery_pitch,
                "entry_offset": entry_offset, "estimated_seconds": estimated_seconds,
                "split_aim": split_aim, "reserve_seconds": reserve,
                "inactive_retreat": parking_info,
                "release_wait_seconds": release_steps / 25,
                "tilt_hold_steps": tilt_hold_steps,
                "grasp_verified": False, "transfer_verified": False,
                "completion_scope": "motion_only", "reached_tcp": arm.tcp()[:3, 3].tolist(),
                "stages": stages}, 0
    except Exception as exc:
        return {"plan_ok": False, "plan_fail_reason": "invalid_arguments" if active == "validate" else "execution_failed",
                "plan_detail": str(exc), "failed_stage": active, "stages": stages}, 2
