"""Bounded vertical grasp/transfer with camera-only lift evidence."""
import io
import base64
import importlib.util
import math
import weakref
from pathlib import Path

import numpy as np
from PIL import Image, ImageDraw

TOOL = {"name": "checked_transfer", "commands": [{
    "name": "grasp-transfer", "budget": True,
    "help": "Vertical grasp, visual lift check, elevated transfer and release",
    "args": [
        {"name": "arm", "positional": True, "choices": ["left", "right"]},
        *[{"name": k, "type": "float", "required": True}
          for k in ("x", "y", "z", "to_x", "to_y", "to_z", "floor_z")],
        {"name": "roi", "required": True},
        {"name": "open", "default": "x", "choices": ["x", "y"]},
        {"name": "approach", "default": "down", "choices": ["down", "down45"]},
        {"name": "yaw", "type": "float", "default": 0.0},
        {"name": "clearance", "type": "float", "default": 0.10},
        {"name": "release_above", "type": "float", "default": 0.04},
        {"name": "landing_floor_z", "type": "float", "default": None},
        {"name": "via", "default": ""},
    ]}]}

TOOL["commands"].extend([
    {"name": "transfer-check", "budget": False,
     "help": "Motionless reachability and action-cost check for an explicit transfer",
     "args": [a.copy() for a in TOOL["commands"][0]["args"]]},
    {"name": "grasp-geometry", "budget": False,
     "help": "Estimate a vertical pinch center and narrow closing axis from an RGB-D crop",
     "args": [{"name": "roi", "required": True},
              {"name": "floor_z", "type": "float", "required": True}]},
    {"name": "roi-transfer", "budget": True,
     "help": "Fit a level-finger grasp from a crop, then visually checked transfer",
     "args": [a.copy() for a in TOOL["commands"][0]["args"]
              if a["name"] not in ("x", "y", "z", "open", "approach", "yaw")]},
])

TOOL["commands"].append({"name": "roi-check", "budget": False,
    "help": "Fit and check vertical and level-finger tilted candidates without motion",
    "args": [a.copy() for a in TOOL["commands"][-1]["args"]]})


for spec in TOOL["commands"]:
    if spec["name"] in ("grasp-geometry", "roi-check", "roi-transfer"):
        spec["args"].extend([
            {"name": "plane_roi", "default": ""},
            {"name": "height", "type": "float", "default": None},
        ])
    if spec["name"] == "grasp-geometry":
        spec["args"].append({"name": "fit_image", "type": "int", "default": 0,
                             "choices": [0, 1]})


# Use the same tool-owned initialization evidence as guarded rotations.
# Only public robot handles and clocks enter this weak, episode-local cache.
_visual_path = Path(__file__).resolve().parents[1] / "vision_checks" / "tool.py"
_visual_spec = importlib.util.spec_from_file_location("transfer_visual_gate", _visual_path)
_visual_module = importlib.util.module_from_spec(_visual_spec)
_visual_spec.loader.exec_module(_visual_module)
_completed_transfers = _visual_module._completed_transfers
continuation_ready = _visual_module.continuation_ready
_failed_poses = weakref.WeakKeyDictionary()


def failed_poses(api, arm):
    """Only measured tool failures, scoped to live handles and a monotone clock."""
    try:
        now = api.sim_time_left()
        saved = _failed_poses.get(arm)
        peer = api.arm("right" if arm is api.arm("left") else "left")
        if (saved and saved[0]() is peer and math.isfinite(now)
                and 0 <= now <= saved[1] and not api.over):
            _failed_poses[arm] = (saved[0], now, saved[2])
            return saved[2]
        _failed_poses.pop(arm, None)
    except Exception:
        pass
    return []


def remember_failure(api, arm, name, pose):
    if name not in ("rotate", "above", "descend"):
        return
    try:
        rows = list(failed_poses(api, arm))
        rows.append((name, pose.copy()))
        peer = api.arm("right" if arm is api.arm("left") else "left")
        _failed_poses[arm] = (weakref.ref(peer), api.sim_time_left(), rows[-16:])
    except Exception:
        pass


def budget_ok(api, preview, include_gate):
    remaining = max(0, int(api.sim_time_left() * 25))
    gate_steps = (10 if continuation_ready(api) else 50) if include_gate else 0
    required = int(preview["transfer_action_steps"]) + gate_steps + 150
    preview.update(home_reserve_steps=150, required_action_steps=required,
                   remaining_action_steps=remaining, budget_ok=remaining >= required)
    return remaining >= required


def visual_gate(api):
    continuation = continuation_ready(api)
    # A failed quietness check invalidates initialization. A later manipulation
    # failure does not erase a completed quiet interval; the next call must
    # still pass a fresh full-image settling check before it can move.
    try:
        _completed_transfers.pop(api.arm("left"), None)
    except TypeError:
        pass
    report, code = _visual_module.run(api, "wait-still", {
        "camera": "head", "quiet": .4 if continuation else 2, "timeout": 6})
    if not code and report.get("plan_ok") and not api.over:
        try:
            _completed_transfers[api.arm("left")] = (
                weakref.ref(api.arm("right")), api.sim_time_left())
        except Exception:
            pass
    report["gate_mode"] = "continuation_settling" if continuation else "full_quietness"
    return report, code


def cloud(obs, camera="cam_head"):
    depth = np.asarray(obs["depth"][camera], dtype=float)
    model = obs["cameras"][camera]
    k = np.asarray(model["intrinsics"], dtype=float)
    transform = np.asarray(model["extrinsics_world"], dtype=float)
    if depth.ndim != 2 or k.shape != (3, 3) or transform.shape != (4, 4):
        raise ValueError("invalid_camera_geometry")
    if not np.isfinite(k).all() or not np.isfinite(transform).all():
        raise ValueError("nonfinite_camera_geometry")
    with Image.open(io.BytesIO(obs["png"][camera])) as image:
        rgb = np.asarray(image.convert("RGB"), dtype=float)
    if rgb.shape[:2] != depth.shape:
        raise ValueError("rgb_depth_size_mismatch")
    v, u = np.indices(depth.shape)
    rays = np.linalg.solve(k, np.stack([u.ravel(), v.ravel(), np.ones(depth.size)]))
    xyz = rays * (depth.ravel() / rays[2])
    world = transform @ np.vstack([xyz, np.ones(depth.size)])
    points = (world[:3] / world[3]).T.reshape(*depth.shape, 3)
    valid = np.isfinite(points).all(axis=2) & np.isfinite(depth) & (depth > 0)
    return points, rgb, valid


def template(obs, roi, goal, floor):
    points, rgb, valid = cloud(obs)
    x0, y0, x1, y1 = roi
    h, w = valid.shape
    if not (0 <= x0 < x1 <= w and 0 <= y0 < y1 <= h):
        raise ValueError("invalid_roi")
    mask = np.zeros_like(valid)
    mask[y0:y1, x0:x1] = True
    mask &= valid & (points[:, :, 2] > floor + 0.006)
    mask &= np.linalg.norm(points[:, :, :2] - goal[:2], axis=2) < 0.07
    mask &= np.abs(points[:, :, 2] - goal[2]) < 0.07
    p, c = points[mask], rgb[mask]
    if len(p) < 12:
        raise ValueError("insufficient_visible_surface")
    stride = max(1, math.ceil(len(p) / 120))
    return p[::stride], c[::stride]


def color_foreground(rgb, background, spread):
    """Discount multiplicative shading only on a distinctly colored plane.

    Neutral/different-hue dark material remains foreground. Near-black pixels
    have unreliable chromaticity and are deliberately not classified as shade.
    This is an RGB heuristic, not evidence that a same-colored item is absent.
    """
    contrast = np.linalg.norm(rgb - background, axis=2) > max(35., spread + 20.)
    shade = np.zeros(contrast.shape, dtype=bool)
    if np.max(background) - np.min(background) > .18 * max(1., np.max(background)):
        scale = (rgb @ background) / max(1., float(background @ background))
        residual = np.linalg.norm(rgb - scale[:, :, None] * background, axis=2)
        shade = ((scale >= .15) & (scale < .95)
                 & (residual <= .08 * np.maximum(np.linalg.norm(rgb, axis=2), 1.)))
    return contrast & ~shade, int(np.count_nonzero(contrast & shade))


def fit_projection(obs, roi, rc, center, top, rgb, with_image):
    """Expose the actual calibrated pinch and fitted pixels for visual review."""
    model = obs["cameras"]["cam_head"]
    xyz = np.array([center, [center[0], center[1], top]])
    local = np.linalg.solve(np.asarray(model["extrinsics_world"]),
                            np.column_stack([xyz, np.ones(2)]).T)[:3]
    uvw = np.asarray(model["intrinsics"]) @ local
    if not np.isfinite(uvw).all() or np.any(local[2] <= 0):
        raise ValueError("invalid_fit_projection")
    uv = (uvw[:2] / uvw[2]).T
    report = dict(pinch_pixel=uv[0].tolist(), top_center_pixel=uv[1].tolist())
    if with_image:
        x0, y0, x1, y1 = roi
        crop = rgb[y0:y1, x0:x1].copy()
        crop[rc[:, 0], rc[:, 1]] = .65 * crop[rc[:, 0], rc[:, 1]] + .35 * np.array([255, 255, 0])
        im = Image.fromarray(crop.astype(np.uint8))
        draw = ImageDraw.Draw(im)
        for pixel, color in zip(uv, ("red", "cyan")):
            u, v = pixel - [x0, y0]
            draw.line((u-4, v, u+4, v), fill=color)
            draw.line((u, v-4, u, v+4), fill=color)
        stream = io.BytesIO()
        im.save(stream, format="PNG")
        report["fit_image_b64"] = base64.b64encode(stream.getvalue()).decode()
    return report


def regional_plane(points, rgb, valid, roi, box, background, patch_z):
    """Cross-check a small patch against distributed, similarly colored tiles.

    Equal tile votes prevent one dense patch dominating the height. Exclude
    the complete source crop, not just its estimated foreground. No object
    depth, caller's guessed floor, or persistent episode cache sets this fit.
    """
    x0, y0, x1, y1 = roi
    a, b, c, d = box
    pad = max(x1-x0, y1-y0, c-a, d-b)
    h, w = valid.shape
    left, right = max(0, min(x0, a)-pad), min(w, max(x1, c)+pad)
    top, bottom = max(0, min(y0, b)-pad), min(h, max(y1, d)+pad)
    matching = valid & (np.linalg.norm(rgb-background, axis=2) <= 25.)
    matching[y0:y1, x0:x1] = False
    # At most 64 nonoverlapping tiles, each with broad uniform coverage.
    xs = np.linspace(left, right, 9, dtype=int)
    ys = np.linspace(top, bottom, 9, dtype=int)
    votes = []
    for row in range(8):
        for col in range(8):
            mask = matching[ys[row]:ys[row+1], xs[col]:xs[col+1]]
            if mask.sum() < max(25, .8 * mask.size):
                continue
            z = points[ys[row]:ys[row+1], xs[col]:xs[col+1], 2][mask]
            if np.percentile(z, 90)-np.percentile(z, 10) <= .02:
                votes.append((row, col, float(np.median(z))))
    report = dict(patch_z=float(patch_z), candidate_tiles=len(votes),
                  method="patch_only", consensus_tiles=0)
    if len(votes) < 6:
        return patch_z, report
    heights = np.array([v[2] for v in votes])
    # Select a dominant horizontal level rather than averaging two levels.
    groups = [np.abs(heights-z) <= .01 for z in heights]
    group = max(groups, key=np.count_nonzero)
    selected = [v for v, keep in zip(votes, group) if keep]
    report["consensus_tiles"] = len(selected)
    if len(selected) < max(6, math.ceil(.7 * len(votes))):
        # A smooth network-depth ramp need not have a dominant 20 mm band.
        # Diagnose that separately from steps/multiple levels. Fit all votes:
        # discarding outliers here could conceal a genuine second surface.
        rows = np.array([v[0] for v in votes], dtype=float)
        cols = np.array([v[1] for v in votes], dtype=float)
        design = np.column_stack([np.ones(len(votes)), rows, cols])
        coef, _, rank, _ = np.linalg.lstsq(design, heights, rcond=None)
        residual = np.abs(heights - design @ coef)
        drift = float(7 * (abs(coef[1]) + abs(coef[2])))
        if (len(votes) < 12 or rank != 3 or
                len(set(rows)) < 4 or len(set(cols)) < 4 or
                np.percentile(residual, 90) > .004 or residual.max() > .008 or
                drift > .05):
            raise ValueError("plane_consensus_ambiguous")
        # Keep a horizontal physical plane, using equal-vote regional median;
        # never extrapolate the apparent slope into the excluded source crop.
        measured = float(np.median(heights))
        if abs(measured-patch_z) > .06:
            raise ValueError("plane_patch_disagrees_with_region")
        report.update(method="regional_smooth_depth", consensus_z=measured,
                      correction_m=measured-patch_z, smooth_tiles=len(votes),
                      depth_drift_m=drift, residual_p90_m=float(np.percentile(residual, 90)),
                      residual_max_m=float(residual.max()))
        return measured, report
    if len({v[0] for v in selected}) < 3 or len({v[1] for v in selected}) < 3:
        return patch_z, report
    measured = float(np.median(heights[group]))
    if abs(measured-patch_z) > .06:
        raise ValueError("plane_patch_disagrees_with_region")
    report.update(method="regional_consensus", consensus_z=measured,
                  correction_m=measured-patch_z)
    return measured, report


def grasp_geometry(obs, roi, floor, plane_roi="", height=None, fit_image=False, trace=None):
    """Fit one isolated visible component; no semantic or hidden-pose inference."""
    points, rgb, valid = cloud(obs)
    x0, y0, x1, y1 = roi
    h, w = valid.shape
    if not math.isfinite(floor) or not (0 <= x0 < x1 <= w and 0 <= y0 < y1 <= h):
        raise ValueError("invalid_roi_or_floor")
    constrained = bool(plane_roi) or height is not None
    shaded_pixels = 0
    plane_measurement = None
    if constrained:
        if not plane_roi or height is None or not math.isfinite(float(height)) or not .008 <= float(height) <= .14:
            raise ValueError("plane_roi_and_height_required")
        height = float(height)
        box = tuple(int(v) for v in plane_roi.split(","))
        if len(box) != 4:
            raise ValueError("invalid_plane_roi")
        a, b, c, d = box
        if not (0 <= a < c <= w and 0 <= b < d <= h) or (a < x1 and c > x0 and b < y1 and d > y0):
            raise ValueError("invalid_plane_roi")
        good = valid[b:d, a:c]
        if good.sum() < max(25, .8 * good.size):
            raise ValueError("plane_depth_missing")
        z = points[b:d, a:c, 2][good]
        floor = float(np.median(z))
        if np.percentile(z, 90) - np.percentile(z, 10) > .02:
            raise ValueError("plane_depth_inconsistent")
        colors = rgb[b:d, a:c][good]
        background = np.median(colors, axis=0)
        spread = float(np.percentile(np.linalg.norm(colors - background, axis=1), 90))
        if spread > 30:
            raise ValueError("plane_appearance_inconsistent")
        floor, plane_measurement = regional_plane(
            points, rgb, valid, roi, box, background, floor)
        foreground, shaded_pixels = color_foreground(rgb[y0:y1, x0:x1], background, spread)
        # Intersect calibrated RGB rays with the caller's top-height constraint.
        # Object depth is never used for these XY coordinates.
        model = obs["cameras"]["cam_head"]
        transform = np.asarray(model["extrinsics_world"], dtype=float)
        rows, cols = np.indices(foreground.shape)
        rays = np.linalg.solve(np.asarray(model["intrinsics"], dtype=float),
                               np.array([(cols+x0).ravel(), (rows+y0).ravel(), np.ones(rows.size)]))
        rays = (transform[:3, :3] @ rays).T
        origin = transform[:3, 3]
        if np.any(np.abs(rays[:, 2]) < 1e-6):
            raise ValueError("plane_ray_parallel")
        distance = (floor + height - origin[2]) / rays[:, 2]
        if np.any(distance <= 0):
            raise ValueError("plane_behind_camera")
        p = (origin + rays * distance[:, None]).reshape(*foreground.shape, 3)
    else:
        p, valid = points[y0:y1, x0:x1], valid[y0:y1, x0:x1]
        foreground = valid & (p[:, :, 2] > floor + .004)
        if np.count_nonzero(valid & (np.abs(p[:, :, 2] - floor) <= .004)) < 12:
            raise ValueError("plane_not_visible_in_crop")
    unseen = foreground.copy()
    components = []
    for row, col in zip(*np.nonzero(foreground)):
        if not unseen[row, col]:
            continue
        pending, component = [(row, col)], []
        unseen[row, col] = False
        while pending:
            r, c = pending.pop()
            component.append((r, c))
            for nr, nc in ((r-1, c), (r+1, c), (r, c-1), (r, c+1)):
                if (0 <= nr < unseen.shape[0] and 0 <= nc < unseen.shape[1]
                        and unseen[nr, nc] and np.linalg.norm(p[nr, nc] - p[r, c]) < .02):
                    unseen[nr, nc] = False
                    pending.append((nr, nc))
        if len(component) >= 12:
            components.append(component)
    components.sort(key=len, reverse=True)
    if not components:
        raise ValueError("insufficient_visible_surface")
    if len(components) > 1 and len(components[1]) >= max(12, .10 * len(components[0])):
        raise ValueError("multiple_surfaces_in_crop")
    rc = np.asarray(components[0])
    if trace is not None:
        # Internal, image-only evidence for bounded crop refinement. Capture
        # before rejecting truncation; never expose a partial pinch as valid.
        trace.update(pixels=rc + [y0, x0], floor_z=float(floor),
                     edges=[bool(np.any(rc[:, 1] == 0)),
                            bool(np.any(rc[:, 0] == 0)),
                            bool(np.any(rc[:, 1] == unseen.shape[1]-1)),
                            bool(np.any(rc[:, 0] == unseen.shape[0]-1))])
    if np.any((rc == 0) | (rc == np.array(unseen.shape) - 1)):
        raise ValueError("surface_cut_by_crop")
    surface = p[rc[:, 0], rc[:, 1]]
    lower, upper = np.percentile(surface, [2, 98], axis=0)
    width = upper[:2] - lower[:2]
    height = upper[2] - floor
    if min(width) < .006 or max(width) > .20 or not .008 <= height <= .14:
        raise ValueError("unsuitable_visible_geometry")
    center = np.r_[(lower[:2] + upper[:2]) / 2, floor + height / 2]
    candidates = vertical_candidates(surface[:, :2])
    return dict(vertical_candidates=candidates, grasp_xyz=center.tolist(), open="x" if width[0] <= width[1] else "y",
                approach="down", visible_bounds=[lower.tolist(), upper.tolist()],
                visible_width_xy=width.tolist(), height_m=float(height), pixels=len(surface),
                geometry_only=True, holding_verified=False, floor_z=float(floor),
                fit_method="rgb_plane_height" if constrained else "depth",
                plane_measurement=plane_measurement,
                shaded_pixels_removed=shaded_pixels,
                **fit_projection(obs, roi, rc, center, upper[2], rgb, fit_image),
                caveat="Visible bounds and the supplied plane only; occlusion, hollow or flexible shapes can invalidate this pinch estimate.")


def rgb_lift_reference(obs, roi, plane_roi, geometry):
    """Bounded RGB samples on the fitted top plane, independent of object depth."""
    if not geometry or geometry.get("fit_method") != "rgb_plane_height":
        return None
    with Image.open(io.BytesIO(obs["png"]["cam_head"])) as im:
        rgb = np.asarray(im.convert("RGB"), dtype=float)
    a, b, c, d = map(int, plane_roi.split(","))
    background = np.median(rgb[b:d, a:c].reshape(-1, 3), axis=0)
    x0, y0, x1, y1 = roi
    crop = rgb[y0:y1, x0:x1]
    mask, _ = color_foreground(crop, background, 0.)
    # Weak contrast cannot reliably distinguish a newly exposed plane.
    mask &= np.max(np.abs(crop - background), axis=2) >= 80
    rows, cols = np.nonzero(mask)
    model = obs["cameras"]["cam_head"]
    transform = np.asarray(model["extrinsics_world"], dtype=float)
    rays = (transform[:3, :3] @ np.linalg.solve(np.asarray(model["intrinsics"]),
            np.array([cols+x0, rows+y0, np.ones(len(rows))]))).T
    origin = transform[:3, 3]
    top = geometry["floor_z"] + geometry["height_m"]
    points = origin + rays * ((top-origin[2]) / rays[:, 2])[:, None]
    lower, upper = np.asarray(geometry["visible_bounds"])
    inside = np.all((points[:, :2] >= lower[:2]) & (points[:, :2] <= upper[:2]), axis=1)
    points, colors = points[inside], crop[rows[inside], cols[inside]]
    if len(points) < 24 or not np.isfinite(points).all():
        return None
    stride = max(1, math.ceil(len(points) / 160))
    return dict(points=points[::stride], colors=colors[::stride], background=background,
                baseline_rgb=rgb, baseline_camera=model)


def rgb_lift_evidence(obs, reference, delta):
    """Require a cleared source and novel elevated RGB with bounded registration.

    A single small camera-plane displacement can account for seating in the
    fingers and plane-height projection error. Never fit samples independently,
    change the source test, or use missing/occluded pixels as positive evidence.
    """
    report = dict(visual_lift_evidence=False, heuristic=True)
    if reference is None:
        return report
    try:
        delta = np.asarray(delta, dtype=float)
        if delta.shape != (3,) or not np.isfinite(delta).all() or delta[2] < .05:
            return report
        with Image.open(io.BytesIO(obs["png"]["cam_head"])) as im:
            rgb = np.asarray(im.convert("RGB"), dtype=float)
        model = obs["cameras"]["cam_head"]
        def project(points, camera=model):
            local = np.linalg.solve(np.asarray(camera["extrinsics_world"]),
                                    np.column_stack([points, np.ones(len(points))]).T)[:3]
            uvw = np.asarray(camera["intrinsics"]) @ local
            return (uvw[:2] / uvw[2]).T, local[2] > 0

        def matches(pixels, front, colors, frame, radius, missing=False):
            # Missing baseline pixels count as pre-existing appearance; missing
            # live pixels count against confirmation. No clipping to the image.
            good = front & np.isfinite(pixels).all(axis=1)
            uv = np.rint(np.where(good[:, None], pixels, 0)).astype(int)
            good &= ((uv[:, 0] >= radius) & (uv[:, 0] < frame.shape[1]-radius)
                     & (uv[:, 1] >= radius) & (uv[:, 1] < frame.shape[0]-radius))
            votes = np.full(len(pixels), missing, dtype=bool)
            dx, dy = np.meshgrid(np.arange(-radius, radius+1), np.arange(-radius, radius+1))
            patch = frame[uv[good, 1, None]+dy.ravel(), uv[good, 0, None]+dx.ravel()]
            close = np.max(np.abs(patch-colors[good, None]), axis=2) <= 35
            votes[good] = np.sum(close, axis=1) >= math.ceil(.6*close.shape[1])
            return votes

        points = reference["points"]
        n = len(points)
        if n < 24:
            return report
        source, source_front = project(points)
        lifted, lifted_front = project(points + delta)
        usable = source_front & lifted_front & (np.linalg.norm(lifted-source, axis=1) >= 8)
        background = np.broadcast_to(reference["background"], (n, 3))
        cleared = matches(source, source_front, background, rgb, 1) & usable

        def elevated(offset):
            expected = points + delta + offset
            live, front = project(expected)
            before, before_front = project(expected, reference["baseline_camera"])
            separated = source_front & front & (np.linalg.norm(live-source, axis=1) >= 8)
            matched = matches(live, front, reference["colors"], rgb, 2) & separated
            prior = matches(before, before_front, reference["colors"], reference["baseline_rgb"],
                            2, missing=True)
            return float(np.mean(matched)), float(np.mean(prior))

        matched, prior = elevated(np.zeros(3))
        report.update(sample_count=n, source_plane_fraction=float(np.mean(cleared)),
                      elevated_rgb_fraction=matched, baseline_elevated_rgb_fraction=prior,
                      nominal_elevated_rgb_fraction=matched,
                      registration_offset_m=[0., 0., 0.], registration_offset_px=[0, 0])
        def accepted(match, previous):
            return bool(np.mean(cleared) >= .60 and match >= .65 and match-previous >= .40)
        report["visual_lift_evidence"] = accepted(matched, prior)
        if report["visual_lift_evidence"] or np.mean(cleared) < .60:
            return report

        # Search a fixed small disk in image space, converted to one rigid
        # world displacement at median predicted camera depth. The correction
        # is also limited to 25 mm and one quarter of the measured lift.
        transform = np.asarray(model["extrinsics_world"], dtype=float)
        intrinsics = np.asarray(model["intrinsics"], dtype=float)
        local = np.linalg.solve(transform, np.column_stack([points+delta, np.ones(n)]).T)
        depth = float(np.median(local[2]))
        if not math.isfinite(depth) or depth <= 0:
            return report
        shifts = sorted(((u, v) for u in range(-6, 7, 2) for v in range(-6, 7, 2)
                         if 0 < u*u+v*v <= 36), key=lambda x: x[0]**2+x[1]**2)
        for u, v in shifts:
            offset = transform[:3, :3] @ (depth * np.linalg.solve(intrinsics, [u, v, 0.]))
            if np.linalg.norm(offset) > min(.025, .25*delta[2]):
                continue
            corrected, corrected_front = project(points + delta + offset)
            if (not np.all(corrected_front) or not np.isfinite(corrected).all()
                    or np.max(np.linalg.norm(corrected-lifted, axis=1)) > 6. + 1e-8):
                continue
            match, previous = elevated(offset)
            if accepted(match, previous):
                report.update(visual_lift_evidence=True, elevated_rgb_fraction=match,
                              baseline_elevated_rgb_fraction=previous,
                              registration_offset_m=offset.tolist(), registration_offset_px=[u, v])
                break
    except Exception as exc:
        report["reason"] = str(exc) or "invalid_rgb_evidence"
    return report


def receiving_plane_check(points, valid, lo, hi, height):
    """Require distributed visible plane evidence, not one elevated depth ray."""
    width = hi - lo
    fractions = (np.arange(5) + .5) / 5
    x, y = np.meshgrid(lo[0] + fractions * width[0], lo[1] + fractions * width[1])
    samples = np.column_stack([x.ravel(), y.ravel()])
    # Separate neighborhoods prevent one small patch from voting for the
    # whole footprint. Missing depth and occlusion supply no positive vote.
    radius = np.minimum(.008, width * .08)
    near_plane = points[valid & (np.abs(points[:, :, 2] - height) <= .004)]
    covered = np.zeros(25, dtype=bool)
    for i, xy in enumerate(samples):
        covered[i] = np.any(np.all(np.abs(near_plane[:, :2] - xy) <= radius, axis=1))
    confirmed = bool(covered.sum() >= 20 and covered[[0, 4, 12, 20, 24]].all())
    return dict(confirmed=confirmed, covered_samples=int(covered.sum()), total_samples=25,
                sample_xy=samples.tolist(), covered=covered.tolist(),
                height_tolerance_m=.004, neighborhood_xy_m=radius.tolist())


def destination_check(obs, reference, goal, dest, floor, geometry=None, release_above=0.,
                      landing_floor_z=None, cloud_data=None):
    """Reject visible raised surfaces in the translated solid footprint.

    This checks the falling volume down to an independently specified plane.
    Missing/occluded geometry is not evidence of a clear landing. Bounds are
    conservative for hollow shapes; no semantic destination inference is made.
    """
    if geometry is not None:
        lower, upper = np.asarray(geometry["visible_bounds"], dtype=float)
    else:
        lower, upper = np.min(reference, axis=0), np.max(reference, axis=0)
    lo = dest[:2] + lower[:2] - goal[:2] - .005
    hi = dest[:2] + upper[:2] - goal[:2] + .005
    # Release height is not a landing plane. Raising either to_z or
    # release_above must never remove obstacles below the release volume.
    # A different receiving plane must be supplied independently in world z.
    bottom = dest[2] + floor - goal[2]
    top = dest[2] + upper[2] - goal[2]
    landing_floor = floor if landing_floor_z is None else float(landing_floor_z)
    if not math.isfinite(landing_floor) or landing_floor > bottom + .010:
        raise ValueError("invalid_landing_floor_z")
    swept_bottom = min(bottom, landing_floor)
    points, _, valid = cloud(obs) if cloud_data is None else cloud_data
    # Only a plane that materially raises the obstruction sweep needs this
    # additional evidence. Same/lower planes retain the conservative sweep.
    plane_check = None
    if swept_bottom > floor + .010:
        plane_check = receiving_plane_check(points, valid, lo + .005, hi - .005,
                                            landing_floor)
    mask = (valid & np.all(points[:, :, :2] >= lo, axis=2)
            & np.all(points[:, :, :2] <= hi, axis=2)
            & (points[:, :, 2] > swept_bottom + .010)
            & (points[:, :, 2] <= top + release_above + .010))
    # Count occupied 3 mm world cells, not camera pixels: a single noisy
    # depth ray or a tiny raster cluster must not veto a transfer.
    hits = points[mask]
    cells = len(np.unique(np.floor(hits / .003).astype(np.int64), axis=0))
    blocked = cells >= 6
    return dict(clear_of_visible_obstructions=not blocked,
                receiving_plane_check=plane_check,
                receiving_plane_ok=plane_check is None or plane_check["confirmed"],
                occupied_cells=cells, footprint_xy=[lo.tolist(), hi.tolist()],
                nominal_bottom_z=float(bottom), nominal_top_z=float(top),
                landing_floor_z=float(landing_floor), swept_bottom_z=float(swept_bottom),
                obstruction_bounds=([hits.min(axis=0).tolist(), hits.max(axis=0).tolist()]
                                    if len(hits) else None),
                landing_verified=False,
                caveat="Head depth only; hidden surfaces, bounce and hollow shapes remain uncertain.")


def vertical_candidates(xy):
    """Narrow planar PCA axis, nearby headings, and both symmetric finger signs."""
    xy = np.asarray(xy, dtype=float)
    values, vectors = np.linalg.eigh(np.cov(xy.T))
    minor = vectors[:, 0]
    heading = math.atan2(minor[1], minor[0])
    options = []
    for offset in (0, -15, 15, -30, 30):
        angle = heading + math.radians(offset)
        across = np.array([math.cos(angle), math.sin(angle)])
        width = float(np.diff(np.percentile(xy @ across, [2, 98]))[0])
        options.append((angle, width))
    minimum = min(width for _, width in options)
    candidates = []
    for angle, width in sorted(options, key=lambda item: item[1]):
        # Do not sacrifice a narrow pinch just to obtain an IK solution.
        if width > minimum * 1.25 + .004:
            continue
        for sign in (0, math.pi):
            yaw = (math.degrees(angle + sign) + 180) % 360 - 180
            candidates.append(dict(yaw_deg=yaw, visible_width_m=width))
    return candidates


def vertical_rotation(yaw, tilt=0.):
    """Tilt the approach about the horizontal closing axis, keeping tips level.

    Unlike projecting a world axis onto a tilted approach plane, this never
    gives the closing axis a vertical component. Signed tilt explores both
    directions perpendicular to the visible narrow axis.
    """
    angle = math.radians(yaw)
    across = np.array([math.cos(angle), math.sin(angle), 0.])
    lean = np.array([-math.sin(angle), math.cos(angle), 0.])
    radians = math.radians(tilt)
    down = np.array([0., 0., -math.cos(radians)]) + math.sin(radians) * lean
    return np.stack([down, across, np.cross(down, across)], axis=1)


def fit_route(api, arm, geometry, goal, dest, clearance, via, release_above=0., pickup_only=False):
    """Read-only bounded search; never attempt an infeasible candidate physically."""
    initial = arm.tcp()
    attempts = []
    candidates = geometry["vertical_candidates"]
    # Width first; prefer the smaller wrist rotation within each symmetric pair.
    candidates = sorted(candidates, key=lambda c: (
        c["visible_width_m"], -np.trace(initial[:3, :3].T @ vertical_rotation(c["yaw_deg"]))))
    if not candidates:
        raise ValueError("no_grasp_candidates")
    # Compare both signs at a given absolute tilt, including a combined
    # elevated translation/rotation. Every candidate gets full-route IK.
    for tilts in ((0.,), (30., -30.), (45., -45.)):
        feasible = []
        for tilt in tilts:
            for setup in ("rotate_first", "translate_first", "combined"):
                for candidate in candidates:
                    rotation = vertical_rotation(candidate["yaw_deg"], tilt)
                    choice = dict(candidate, tilt_deg=tilt, setup=setup,
                                  approach="down" if tilt == 0 else "tilted_level_fingers",
                                  approach_direction=rotation[:, 0].tolist(),
                                  closing_direction=rotation[:, 1].tolist())
                    route = transfer_route(initial, goal, dest, clearance, via, "down", "x",
                                           rotation=rotation, release_above=release_above,
                                           setup=setup)
                    if pickup_only:
                        route = route[:next(i for i, (name, _) in enumerate(route) if name == "lift") + 1]
                    report = preflight(api, arm, route)
                    attempts.append(dict(**choice, estimate_ok=bool(report.get("estimate_ok")),
                                         reason=report.get("reason"), failed_stage=report.get("failed_stage")))
                    if report.get("estimate_ok"):
                        feasible.append((route, report, choice))
        if feasible:
            # Compare costs within the least-tilted feasible tier. This is free
            # IK work, not another physical attempt or a cached executable plan.
            route, report, choice = min(feasible, key=lambda r: r[1]["transfer_action_steps"])
            report["selected_grasp"] = choice
            report["candidate_checks"] = attempts
            return route, report
    report["candidate_checks"] = attempts
    return route, report


def matching_mask(points, colors, valid, reference, appearance, delta):
    expected = reference + delta
    lower, upper = expected.min(axis=0) - 0.015, expected.max(axis=0) + 0.015
    mask = valid & np.all((points >= lower) & (points <= upper), axis=2)
    candidates, shades = points[mask], colors[mask]
    matched = np.zeros(len(reference), dtype=bool)
    if len(candidates) == 0:
        return matched
    # Bounded memory even for a large image; each reference point votes once.
    for i, (point, color) in enumerate(zip(expected, appearance)):
        close = np.linalg.norm(candidates - point, axis=1) < 0.015
        same_color = np.max(np.abs(shades - color), axis=1) < 45
        matched[i] = bool(np.any(close & same_color))
    return matched


def matching_fraction(points, colors, valid, reference, appearance, delta):
    matched = matching_mask(points, colors, valid, reference, appearance, delta)
    return float(matched.mean()) if len(matched) else 0.0


def occluded_reference(obs, expected):
    """Excuse only points hidden by a nearer measured surface, never missing depth.

    Require a full 3x3 patch to be nearer, avoiding silhouette-edge rounding.
    Out-of-frame and invalid pixels remain unexplained missing evidence.
    """
    model = obs["cameras"]["cam_head"]
    depth = np.asarray(obs["depth"]["cam_head"], dtype=float)
    camera = np.linalg.solve(np.asarray(model["extrinsics_world"], dtype=float),
                             np.vstack([expected.T, np.ones(len(expected))]))
    camera = camera[:3] / camera[3]
    projected = np.asarray(model["intrinsics"], dtype=float) @ camera
    hidden = np.zeros(len(expected), dtype=bool)
    for i in range(len(expected)):
        if camera[2, i] <= 0 or not np.isfinite(projected[:, i]).all():
            continue
        u, v = np.rint(projected[:2, i] / projected[2, i]).astype(int)
        if not (1 <= u < depth.shape[1] - 1 and 1 <= v < depth.shape[0] - 1):
            continue
        patch = depth[v-1:v+2, u-1:u+2]
        hidden[i] = bool(np.all(np.isfinite(patch) & (patch > 0)
                               & (patch < camera[2, i] - .025)))
    return hidden


def source_consistency(obs, points, valid, reference):
    """Exclude alternate-view source samples inside head-camera free space.

    A nearby RGB match is not a surface if another calibrated camera sees
    beyond it. Require all nine neighboring depth rays to agree, with a 5 mm
    margin. Occlusion, missing depth and image edges cannot clear a sample.
    Only the source neighborhood is projected, bounding work and memory.
    """
    lower, upper = reference.min(axis=0) - .015, reference.max(axis=0) + .015
    selected = valid & np.all((points >= lower) & (points <= upper), axis=2)
    rows, cols = np.nonzero(selected)
    if not len(rows):
        return valid, 0
    model = obs['cameras']['cam_head']
    depth = np.asarray(obs['depth']['cam_head'], dtype=float)
    xyz = points[rows, cols]
    camera = np.linalg.solve(np.asarray(model['extrinsics_world'], dtype=float),
                             np.vstack([xyz.T, np.ones(len(xyz))]))
    camera = camera[:3] / camera[3]
    projected = np.asarray(model['intrinsics'], dtype=float) @ camera
    usable = (camera[2] > 0) & np.isfinite(projected).all(axis=0)
    indices = np.flatnonzero(usable)
    uv = np.rint(projected[:2, indices] / projected[2, indices]).T
    inside = ((uv[:, 0] >= 1) & (uv[:, 0] < depth.shape[1] - 1)
              & (uv[:, 1] >= 1) & (uv[:, 1] < depth.shape[0] - 1))
    indices, uv = indices[inside], uv[inside].astype(int)
    clear = np.ones(len(indices), dtype=bool)
    for dy in (-1, 0, 1):
        for dx in (-1, 0, 1):
            measured = depth[uv[:, 1] + dy, uv[:, 0] + dx]
            clear &= np.isfinite(measured) & (measured > 0) & (measured > camera[2, indices] + .005)
    rejected = indices[clear]
    filtered = valid.copy()
    filtered[rows[rejected], cols[rejected]] = False
    return filtered, int(len(rejected))


def evidence(obs, reference, appearance, delta, floor_z=None):
    # Use the same above-plane predicate as template extraction. A 15 mm
    # positional match alone mistakes the exposed plane under thin surfaces
    # for a source that never moved, especially in a second camera view.
    def source_fraction(points, colors, valid):
        if floor_z is not None:
            valid = valid & (points[:, :, 2] > floor_z + .006)
        return matching_fraction(points, colors, valid, reference, appearance, np.zeros(3))

    points, colors, valid = cloud(obs)
    matched = matching_mask(points, colors, valid, reference, appearance, delta)
    original = source_fraction(points, colors, valid)
    cameras = {"cam_head": float(matched.mean())}
    source_cameras = {"cam_head": original}
    source_conflicts = {}
    skipped = {}
    # References remain in world coordinates. A second calibrated view may
    # reveal the same surface behind the fingers, without moving either arm.
    # Union per-reference votes, not counts: repeated views cannot inflate them.
    for camera in ("cam_left_wrist", "cam_right_wrist"):
        try:
            p, c, v = cloud(obs, camera)
            votes = matching_mask(p, c, v, reference, appearance, delta)
            source_valid, conflicts = source_consistency(obs, p, v, reference)
            source = source_fraction(p, c, source_valid)
        except Exception as exc:
            skipped[camera] = str(exc) or "invalid_camera"
            continue
        cameras[camera] = float(votes.mean())
        source_cameras[camera] = source
        source_conflicts[camera] = conflicts
        matched |= votes
        # A geometrically consistent source in ANY view can veto a lift.
        original = max(original, source)
    moved = float(matched.mean()) if len(matched) else 0.0
    visible = ~occluded_reference(obs, reference + delta)
    count = int(visible.sum())
    # A 15 mm neighborhood can contain a genuine match even when the exact
    # projected ray hits a nearer occluder. Positive RGB-D evidence must not
    # be discarded by that approximate visibility test. Only unmatched hidden
    # references are excused; unmatched visible references remain penalties.
    evidence_visible = visible | matched
    evidence_count = int(evidence_visible.sum())
    visible_match = float(matched.sum() / evidence_count) if evidence_count else 0.
    # Occlusion alone is never positive evidence. Keep an absolute match floor
    # and sufficient visible samples in addition to the normalized fraction.
    enough = evidence_count >= max(12, math.ceil(.30 * len(reference)))
    confirmed = moved >= .45 or (enough and moved >= .30 and visible_match >= .60)
    return {"translated_surface_fraction": moved, "original_surface_fraction": original,
            "camera_source_fractions": source_cameras, "source_floor_z": floor_z,
            "camera_source_conflicts": source_conflicts,
            "camera_match_fractions": cameras, "skipped_cameras": skipped,
            "visible_reference_count": count,
            "evidence_reference_count": evidence_count,
            "matched_occluded_reference_count": int(np.count_nonzero(matched & ~visible)),
            "occluded_reference_fraction": float(1 - count / len(reference)),
            "visible_surface_fraction": visible_match,
            "visual_lift_evidence": bool(confirmed and original <= 0.35)}


def transfer_route(initial, goal, dest, clearance, via, approach, axis, yaw=0., rotation=None,
                   release_above=0., setup="rotate_first"):
    """Exact nominal motion targets shared by preview and execution."""
    from roboshell.server.core import tool_rotation
    target = np.asarray(initial, dtype=float).copy()
    if target.shape != (4, 4) or not np.isfinite(target).all():
        raise ValueError("invalid_tcp")
    cruise = max(goal[2], dest[2]) + clearance
    route = []
    def add(name):
        route.append((name, target.copy()))
    target[2, 3] = max(target[2, 3], cruise)
    add("raise")
    if rotation is None:
        angle = math.radians(yaw)
        rz = np.array([[math.cos(angle), -math.sin(angle), 0.],
                       [math.sin(angle), math.cos(angle), 0.], [0., 0., 1.]])
        rotation = rz @ tool_rotation(approach, axis, target[:3, :3])
    if setup == "combined":
        # Both ends are at or above cruise; rotation finishes before descent.
        target[:3, 3] = [goal[0], goal[1], cruise]
        target[:3, :3] = rotation
        add("rotate")
    elif setup == "translate_first":
        target[:3, 3] = [goal[0], goal[1], cruise]
        add("above")
        target[:3, :3] = rotation
        add("rotate")
    elif setup == "rotate_first":
        target[:3, :3] = rotation
        add("rotate")
        target[:3, 3] = [goal[0], goal[1], cruise]
        add("above")
    else:
        raise ValueError("invalid_setup")
    target[:3, 3] = goal
    add("descend")
    target[2, 3] = cruise
    add("lift")
    waypoints = ([np.array([*via, cruise])] if via else []) + [np.array([dest[0], dest[1], cruise])]
    for waypoint in waypoints:
        if np.linalg.norm(waypoint - target[:3, 3]) > 3.0:
            raise ValueError("transfer_too_long")
        # move_tcp already solves the entire straight line at ~2 cm intervals.
        # Splitting it into 15 cm commands adds a full deceleration/acceleration
        # at every boundary without changing clearance or the geometric path.
        # Keep caller-specified bends, but check retention only at each endpoint.
        target[:3, 3] = waypoint
        add("carry")
    target[:3, 3] = dest
    # Shorten only the final descent, never raise the entire carry path.
    # The caller can request exact-height release with a zero allowance.
    target[2, 3] += release_above
    add("lower")
    target[2, 3] = cruise
    add("retreat")
    return route


def preflight(api, arm, route):
    for name, pose in route:
        for failed_name, failed_pose in failed_poses(api, arm):
            cosine = np.clip((np.trace(pose[:3, :3].T @ failed_pose[:3, :3])-1)/2, -1, 1)
            if (name == failed_name and np.linalg.norm(pose[:3, 3]-failed_pose[:3, 3]) < .025
                    and np.degrees(np.arccos(cosine)) < 10):
                return dict(estimate_ok=False, reason="previous_tracking_failure",
                            failed_stage=name, estimate_only=True)
    report = dict(api.estimate_tcp_chain(arm, route))
    # The API counts close/release; this tool also opens before approach.
    if report.get("estimate_ok"):
        extra = int(report["gripper_action_steps"]) // 2
        report["transfer_action_steps"] += extra
        report["total_action_steps"] += extra
        report["gripper_action_steps"] += extra
    report["quiet_gate_action_steps_range"] = [10 if continuation_ready(api) else 50, 150]
    report["note"] = ("IK and conservative nominal cost only; no collision or grasp certificate. "
                      "Quiet-gate steps are additional; actual tracking and settling may differ. "
                      "Recomputed before execution; no cached executable plan.")
    return report


def run(api, command, args):
    pickup_only = command in ("roi-pick", "pick-check")
    fitted = command in ("roi-transfer", "roi-check", "grasp-geometry", "roi-pick", "pick-check")
    stages, checks = [], []
    gate = None
    start = None
    geometry = None
    preview = None
    destination = None
    def result(reason=None):
        # A rejected read-only fit/preflight has not disturbed the scene.
        # Initialization records successful quietness, not grasp success.
        # Failed gates invalidate it; subsequent manipulation errors do not.
        if (reason is not None and command in ("grasp-transfer", "roi-transfer")
                and not continuation_ready(api)):
            try:
                _completed_transfers.pop(api.arm("left"), None)
            except Exception:
                pass
        out = dict(plan_ok=reason is None, plan_fail_reason=reason, stages=stages,
                   visual_checks=checks, released=any(s["stage"] == "release" for s in stages),
                   holding_verified=bool(pickup_only and reason is None and checks
                                         and checks[-1].get("visual_lift_evidence")),
                   visual_gate=gate, grasp_geometry=geometry, preflight=preview,
                   destination_check=destination)
        if start is not None:
            out["action_steps"] = max(0, round((start - api.sim_time_left()) * 25))
        return out, 0 if reason is None else 2
    try:
        if command not in ("grasp-transfer", "roi-transfer", "grasp-geometry", "transfer-check", "roi-check", "roi-pick", "pick-check"):
            return result("unknown_command")
        args = dict(args)
        if args.get("fit_image", 0) not in (0, 1):
            return result("invalid_fit_image")
        if fitted:
            roi = tuple(int(v) for v in args["roi"].split(","))
            if len(roi) != 4:
                return result("invalid_roi")
            geometry = grasp_geometry(api.observe(), roi, float(args["floor_z"]),
                                      args.get("plane_roi", ""), args.get("height"),
                                      bool(args.get("fit_image", 0)))
            args["floor_z"] = geometry["floor_z"]
            if command == "grasp-geometry":
                return result()
            args.update(zip(("x", "y", "z"), geometry["grasp_xyz"]))
            args.update(open=geometry["open"], approach="down")
        goal = np.array([float(args[k]) for k in ("x", "y", "z")])
        dest = goal.copy() if pickup_only else np.array([float(args[k]) for k in ("to_x", "to_y", "to_z")])
        yaw = float(args.get("yaw", 0.))
        floor, clearance = float(args["floor_z"]), float(args.get("clearance", 0.10))
        release_above = float(args.get("release_above", .04))
        landing_floor_z = args.get("landing_floor_z")
        if landing_floor_z is not None:
            landing_floor_z = float(landing_floor_z)
            if not math.isfinite(landing_floor_z):
                return result("invalid_landing_floor_z")
        roi = tuple(int(v) for v in args["roi"].split(","))
        via = [float(v) for v in args.get("via", "").split(",")] if args.get("via") else []
        tag, approach, axis = args["arm"], args.get("approach", "down"), args.get("open", "x")
        if (tag not in ("left", "right") or approach not in ("down", "down45") or axis not in ("x", "y")
                or len(roi) != 4 or len(via) not in (0, 2)
                or not np.isfinite([*goal, *dest, floor, clearance, release_above, yaw, *via]).all()
                or not 0 <= release_above <= min(.06, clearance)
                or not 0.06 <= clearance <= 0.18 or not floor < goal[2] or dest[2] <= floor):
            return result("invalid_arguments")
        if api.over:
            return result("episode_over")
        reference, appearance = template(api.observe(), roi, goal, floor)
        arm = api.arm(tag)
        start = api.sim_time_left()
        if not pickup_only:
            destination = destination_check(api.observe(), reference, goal, dest, floor, geometry,
                                            release_above, landing_floor_z)
            if not destination["clear_of_visible_obstructions"]:
                return result("destination_obstructed")
            if not destination.get("receiving_plane_ok", True):
                return result("landing_plane_unconfirmed")
        def checked_route():
            if fitted:
                if pickup_only:
                    return fit_route(api, arm, geometry, goal, goal, clearance, [], 0., pickup_only=True)
                return fit_route(api, arm, geometry, goal, dest, clearance, via, release_above)
            route = transfer_route(arm.tcp(), goal, dest, clearance, via, approach, axis, yaw,
                                   release_above=release_above)
            return route, preflight(api, arm, route)
        route, preview = checked_route()
        if not preview.get("estimate_ok"):
            return result("preflight_" + (preview.get("reason") or "unreachable"))
        if not budget_ok(api, preview, include_gate=True):
            return result("insufficient_steps_with_home_reserve")
        if command in ("transfer-check", "roi-check", "pick-check"):
            return result()
        gate, code = visual_gate(api)
        if code or not gate.get("plan_ok"):
            return result(gate.get("plan_fail_reason") or "visual_gate_failed")
        if api.over:
            return result("episode_over")
        # Refresh the source after waiting; pre-wait imagery may be stale.
        source_obs = api.observe()
        if command in ("roi-transfer", "roi-pick"):
            geometry = grasp_geometry(source_obs, roi, floor,
                                      args.get("plane_roi", ""), args.get("height"))
            floor = geometry["floor_z"]
            goal = np.array(geometry["grasp_xyz"])
            axis = geometry["open"]
        reference, appearance = template(source_obs, roi, goal, floor)
        if not pickup_only:
            destination = destination_check(api.observe(), reference, goal, dest, floor, geometry,
                                            release_above, landing_floor_z)
            if not destination["clear_of_visible_obstructions"]:
                return result("destination_obstructed")
            if not destination.get("receiving_plane_ok", True):
                return result("landing_plane_unconfirmed")
        rgb_reference = (rgb_lift_reference(source_obs, roi, args.get("plane_roi", ""), geometry)
                         if pickup_only else None)
        route, preview = checked_route()
        if not preview.get("estimate_ok"):
            return result("preflight_" + (preview.get("reason") or "unreachable"))
        if not budget_ok(api, preview, include_gate=False):
            return result("insufficient_steps_with_home_reserve")

        def move(name, pose):
            if api.over:
                raise ValueError("episode_over")
            desired = pose.copy()
            feedback = {}
            code = api.move_tcp(arm, pose.copy(), feedback)
            reached = np.asarray(arm.tcp(), dtype=float)
            error = float(np.linalg.norm(reached[:3, 3] - desired[:3, 3]))
            cosine = np.clip((np.trace(desired[:3, :3].T @ reached[:3, :3]) - 1) / 2, -1, 1)
            angle = float(np.degrees(np.arccos(cosine)))
            stages.append(dict(stage=name, motion=feedback, measured_error_m=error, measured_error_deg=angle))
            if api.over:
                raise ValueError("episode_over")
            if code or not feedback.get("plan_ok"):
                raise ValueError(feedback.get("plan_fail_reason") or "motion_failed")
            if feedback.get("workspace_limited") or not math.isfinite(error) or not math.isfinite(angle) or angle > 5:
                remember_failure(api, arm, name, desired)
                raise ValueError("motion_tracking_error")
            if error > 0.012:
                offset = reached[:3, 3] - desired[:3, 3]
                # The final pickup pose need not hit its nominal height to
                # permit image verification. Bound the undershoot, then reset
                # the controller to the measured pose before taking evidence.
                if (pickup_only and name == "lift" and rgb_reference is not None
                        and geometry.get("fit_method") == "rgb_plane_height"
                        and grasp_tcp is not None
                        and np.linalg.norm(offset[:2]) <= .010
                        and 0 < -offset[2] <= min(.035, clearance / 2)
                        and reached[2, 3] - grasp_tcp[2] >= .05):
                    stages[-1]["lift_shortfall_m"] = float(-offset[2])
                    return reached.copy()
                # A biased plane can put a fitted pinch below physical contact.
                # Pickup-only recovery stops pressing before closure and still
                # requires fresh lift evidence; it never authorizes a carry.
                if (pickup_only and name == "descend" and rgb_reference is not None
                        and geometry.get("fit_method") == "rgb_plane_height"
                        and np.linalg.norm(offset[:2]) <= .010
                        and 0 < offset[2] <= min(.035, clearance / 2)
                        and clearance - offset[2] >= .05
                        and np.all(reached[:2, 3] >= np.asarray(geometry["visible_bounds"][0])[:2])
                        and np.all(reached[:2, 3] <= np.asarray(geometry["visible_bounds"][1])[:2])):
                    stages[-1]["contact_shortfall_m"] = float(offset[2])
                    return reached.copy()
                # A blocked final descent can still leave a usable release pose.
                # Never excuse lateral drift, overshoot, earlier route errors,
                # or a shortfall exceeding half the requested clearance.
                if (name != "lower" or np.linalg.norm(offset[:2]) > .012
                        or not 0 < offset[2] <= min(.04, clearance / 2) - release_above):
                    remember_failure(api, arm, name, desired)
                    raise ValueError("motion_tracking_error")
                return reached.copy()
            return None

        def grip(name, value):
            if api.over or not api.set_gripper(arm, value) or api.over:
                raise ValueError("episode_over")
            stages.append(dict(stage=name))

        grasp_tcp = None
        def check():
            delta = np.asarray(arm.tcp())[:3, 3] - grasp_tcp
            obs = api.observe()
            report = evidence(obs, reference, appearance, delta, floor_z=floor)
            if pickup_only and not report["visual_lift_evidence"] and rgb_reference is not None:
                report["rgb_lift"] = rgb_lift_evidence(obs, rgb_reference, delta)
                if report["rgb_lift"]["visual_lift_evidence"]:
                    report["visual_lift_evidence"] = True
                    report["verification_method"] = "rgb_source_clear_and_elevated_match"
            checks.append(report)
            if not report["visual_lift_evidence"]:
                raise ValueError("visual_grasp_unconfirmed")

        # Execute the same targets that were checked, with live tracking/lift checks.
        for name, target in route:
            elevated_release = move(name, target)
            if name == "rotate":
                grip("open", 1)
            elif name == "descend":
                if elevated_release is not None:
                    # Estimate from the actual pose, including the target reset;
                    # preserve the existing absolute lift and its clearance.
                    recovery = preflight(api, arm, [
                        ("contact_hold", elevated_release), route[-1]])
                    stages[-1]["contact_recovery_preflight"] = recovery
                    if not recovery.get("estimate_ok"):
                        raise ValueError("contact_recovery_unreachable")
                    if not budget_ok(api, recovery, include_gate=False):
                        raise ValueError("insufficient_steps_with_home_reserve")
                    move("contact_hold", elevated_release)
                grip("close", 0)
                grasp_tcp = np.asarray(arm.tcp())[:3, 3].copy()
            elif name in ("lift", "carry"):
                if name == "lift" and elevated_release is not None:
                    recovery = preflight(api, arm, [("lift_hold", elevated_release)])
                    stages[-1]["lift_recovery_preflight"] = recovery
                    if not recovery.get("estimate_ok"):
                        raise ValueError("lift_recovery_unreachable")
                    if not budget_ok(api, recovery, include_gate=False):
                        raise ValueError("insufficient_steps_with_home_reserve")
                    move("lift_hold", elevated_release)
                    if np.asarray(arm.tcp())[2, 3] - grasp_tcp[2] < .05:
                        raise ValueError("insufficient_measured_lift")
                check()
            elif name == "lower":
                stages[-1]["release_above_m"] = release_above
                if release_above > 0:
                    check()
                if elevated_release is not None:
                    # Reconfirm retention at the actual pose before opening.
                    check()
                    recovery = preflight(api, arm, [
                        ("release_hold", elevated_release), route[-1]])
                    stages[-1]["elevated_release_preflight"] = recovery
                    if not recovery.get("estimate_ok"):
                        raise ValueError("elevated_release_unreachable")
                    # Replace the lower controller target before gripper hold,
                    # so release does not keep pressing toward the obstruction.
                    move("release_hold", elevated_release)
                    stages[-1]["release_height_offset_m"] = float(
                        elevated_release[2, 3] - dest[2])
                grip("release", 1)
        try:
            left, right = api.arm("left"), api.arm("right")
            _completed_transfers[left] = (weakref.ref(right), api.sim_time_left())
        except Exception:
            # Caching is optional; unsupported handles retain the full gate.
            pass
        return result()
    except Exception as exc:
        return result(str(exc) or "transfer_error")
