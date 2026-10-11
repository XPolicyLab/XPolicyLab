"""Episode loop run inside the RoboDojo simulation client.

RoboDojo imports this module as ``XPolicyLab.policy.vlm_agent.deploy`` and
calls :func:`eval_one_episode` once per episode, handing over the task
environment and the websocket client to the policy server.

The loop differs from the stock XPolicyLab template because inference costs
seconds rather than milliseconds: the observation is pushed once per *turn*,
not once per control step, and a turn's commands are planned and executed here
in full (RoboDojo's cuRobo planner only exists inside this process) before the
next observation is taken. A turn arrives as a ``sequence`` envelope
(:mod:`motion`): a list of discrete commands that :mod:`main_route` resolves
and executes one after another.
"""

from __future__ import annotations

import importlib
import importlib.util
import json
import math
import os
from pathlib import Path
import time
from types import SimpleNamespace

ENV_IDX = 0  # eval_batch is false, so RoboDojo forces num_envs to 1.

_ik_check_disabled = False
_planner_disabled = False
_gripper_probe_disabled = False
_gripper_floor_disabled = False
_calibration_disabled = False


def _sibling(name: str):
    """Import a module next to this file, however this file was loaded.

    RoboDojo imports it as part of the ``vlm_agent`` package, but the offline
    tests load it straight from disk, where a relative import cannot resolve.
    """
    if __package__:
        return importlib.import_module(f".{name}", __package__)
    spec = importlib.util.spec_from_file_location(
        f"vlm_agent_{name}", Path(__file__).resolve().with_name(f"{name}.py")
    )
    module = importlib.util.module_from_spec(spec)
    spec.loader.exec_module(module)
    return module


motion = _sibling("motion")


def _configure_rpc_timeout(model_client, config):
    """Let one inference call finish its transport retries before the RPC expires."""
    budget = float(config.get("decision_budget_s", 660.0))
    if not math.isfinite(budget) or budget <= 0:
        raise ValueError("decision_budget_s must be finite and positive")
    timeout = budget + 30.0
    # XPolicyLab's websocket adapter exposes its protocol config through _client.
    attributes = vars(model_client)
    rpc_config = getattr(attributes.get("_client"), "config", None)
    if rpc_config is not None:
        rpc_config.request_timeout_s = max(float(rpc_config.request_timeout_s), timeout)
    elif attributes.get("sock") is not None:
        model_client.timeout = max(float(model_client.timeout), timeout)
        model_client.sock.settimeout(model_client.timeout)


def _deploy_yml_block() -> dict:
    """The ``vlm_agent`` block of the deploy.yml next to this file.

    RoboDojo builds ``deploy_cfg`` from its command line alone (policy name,
    port, host, run ids), so the simulation client would otherwise never see
    the yml block and every sim-side knob would run on code defaults while the policy server read the file.
    """
    path = Path(__file__).resolve().with_name("deploy.yml")
    try:
        import yaml
        block = (yaml.safe_load(path.read_text(encoding="utf-8")) or {}).get("vlm_agent") or {}
    except Exception as exc:  # noqa: BLE001 - a missing or unreadable file keeps the defaults, and says so
        print(f"[vlm_agent] {path.name} not read ({type(exc).__name__}: {exc}); sim-side knobs use code defaults",
              flush=True)
        return {}
    return dict(block)


def eval_one_episode(TASK_ENV, model_client):
    """Drive one episode with the VLM policy server."""
    # No `reset` call here: RoboDojo's EvalEnv.reset() already resets the
    # policy right before run_eval(), and a second reset would drop the
    # episode bookkeeping the agent just set up.
    config = _deploy_yml_block()
    config.update(getattr(TASK_ENV, "deploy_cfg", {}).get("vlm_agent") or {})
    config.update(json.loads(os.environ.get("VLM_AGENT_OVERRIDES", "{}")))
    _configure_rpc_timeout(model_client, config)
    global _ik_check_disabled, _calibration_disabled, _gripper_probe_disabled, _gripper_floor_disabled
    _ik_check_disabled = False
    _calibration_disabled = False
    _gripper_probe_disabled = False
    _gripper_floor_disabled = False
    # the poses `home` returns to
    session = {"home_poses": None, "home_joints": None}
    recorder = (_sibling('sft_recording').SFTRecording if os.environ.get('ROBODAWN_SFT_DIR')
                else _sibling('recording').EpisodeRecording)
    with recorder(TASK_ENV, config) as capture:
        capture.decisions = 0
        try:
            _lift_step_limit(TASK_ENV)
            start = _episode_meta(TASK_ENV)
            start["video_capture"] = capture.metadata()
            model_client.call(func_name="report_execution", obs=start)
            report = _eval_episode(TASK_ENV, model_client, config, capture, session)
        except BaseException as exc:
            reason = "interrupted" if isinstance(exc, (KeyboardInterrupt, SystemExit)) else "exception"
            try:
                if not TASK_ENV.is_episode_end():
                    _end_unsuccessful(TASK_ENV)
            except Exception:
                TASK_ENV.success[ENV_IDX] = False
            capture.finish(reason)
            report = _episode_meta(TASK_ENV)
            report.update(phase="episode_end", termination_reason=reason, decisions=capture.decisions,
                          success=bool(TASK_ENV.success[ENV_IDX]), video_capture=capture.metadata())
            try:
                model_client.call(func_name="report_execution", obs=report)
            except Exception:
                pass
            raise
        capture.finish(report["termination_reason"])
        try:
            _sibling("posthoc_checks").write_terminal_checks(TASK_ENV)
        except Exception as exc:
            print(f"[posthoc] terminal checks unavailable: {exc}", flush=True)
        report["video_capture"] = capture.metadata()
        model_client.call(func_name="report_execution", obs=report)


UNBOUNDED_STEPS = 10**9


def _lift_step_limit(TASK_ENV) -> None:
    """Preserve the native per-task budget; retained name for caller compatibility."""
    limit = int(TASK_ENV.step_lim)
    if limit <= 0 or limit >= UNBOUNDED_STEPS:
        raise ValueError(f'Invalid native task step limit: {limit}')
    TASK_ENV.native_step_limit = limit
    print(f'[vlm_agent] enforcing native step limit: {limit}', flush=True)


def _eval_episode(TASK_ENV, model_client, config, capture, session=None):
    max_decisions = int(config.get("max_decisions", 60))
    max_zero_progress = int(config.get("max_zero_progress", 5))
    deadline = time.monotonic() + float(config.get("episode_budget_s", 1800))
    decisions = 0
    zero_progress = 0
    termination = "native"
    measure_gripper = bool(config.get("measure_gripper", True))
    wants_calibration = _wants_calibration(config)
    # Camera poses are re-read below for every observation (the wrist cameras move).
    calibration_cameras = tuple(dict.fromkeys(["cam_head", *(config.get("cameras") or [])]))
    report = _episode_meta(TASK_ENV)
    report.update(phase="episode_start", planner_warmup=_warmup_planner(TASK_ENV))
    print(f"[vlm_agent] cuRobo warmup: {report['planner_warmup']}", flush=True)
    model_client.call(func_name="report_execution", obs=report)

    settle_module = _sibling("gripper_settle")
    commanded_grippers = {}
    if session is None:
        session = {"home_poses": None, "home_joints": None}
    camera_audit = _sibling("classify_camera_audit").CameraAudit(TASK_ENV)
    while not TASK_ENV.is_episode_end():
        if decisions >= max_decisions or zero_progress >= max_zero_progress or time.monotonic() >= deadline:
            termination = ("decision_budget" if decisions >= max_decisions else
                           "zero_progress" if zero_progress >= max_zero_progress else "wall_budget")
            _end_unsuccessful(TASK_ENV)
            break
        obs = TASK_ENV.get_obs()
        obs["policy_budget_s"] = max(0, deadline - time.monotonic())
        if measure_gripper:
            obs["gripper_real"] = _gripper_real(TASK_ENV)
        if measure_gripper:
            obs["gripper_closed_floor"] = _gripper_closed_floor(TASK_ENV)
        if wants_calibration:
            obs["calibration"] = _camera_calibration(TASK_ENV, calibration_cameras)
        try:
            camera_payload = camera_audit.capture(decisions + 1, int(TASK_ENV.take_action_cnt[0]), obs.get("calibration", {}))
            if camera_payload is not None:
                obs["calibration"], obs["calibration_provenance"] = _sibling("classify_render_calibration").derive(camera_payload)
                camera_audit.save_correction(obs["calibration"], obs["calibration_provenance"])
        except Exception as exc:
            if getattr(TASK_ENV, "task_name", None) == "classify_objects_by_language":
                obs["calibration"] = {}
                obs["calibration_provenance"] = {"status": "unavailable_omitted", "reason": str(exc)}
            print(f"[camera_audit] calibration unavailable: {exc}", flush=True)
        for arm, target in settle_module.action_targets(TASK_ENV, obs.get("state") or {}).items():
            commanded_grippers.setdefault(arm, target)
        model_client.call(func_name="update_obs", obs=obs)
        envelope = motion.normalize(model_client.call(func_name="get_action"))

        if envelope["kind"] == motion.KIND_STOP:
            reason = envelope.get("reason") or "no action"
            print(f"[vlm_agent] policy returned no action ({reason}); ending the episode loop", flush=True)
            termination = "policy_stop"
            _end_unsuccessful(TASK_ENV)
            break
        decisions += 1
        capture.decisions = decisions

        report, stopped = _run_sequence(TASK_ENV, envelope, config, capture, deadline, commanded_grippers,
                                        session, settle_module)
        report.update(_episode_meta(TASK_ENV))
        report.pop("phase", None)
        report.update(video_capture=capture.metadata())
        model_client.call(func_name="report_execution", obs=report)
        zero_progress = zero_progress + 1 if report["executed"] == 0 else 0
        if stopped == "wall_budget":
            termination = stopped
            _end_unsuccessful(TASK_ENV)
            break

    report = _episode_meta(TASK_ENV)
    report.update(phase="episode_end", termination_reason=termination, decisions=decisions,
                  success=bool(TASK_ENV.success[ENV_IDX]))
    print(f"[vlm_agent] episode ended: {termination}, decisions={decisions}, "
          f"steps={report['steps_used']}, success={report['success']}", flush=True)
    return report


def _control_stop_reason(env, deadline):
    if env.is_episode_end():
        return "native"
    if time.monotonic() >= deadline:
        return "wall_budget"
    return None


def _execute_control(env, action, report, settle, settle_module, *, added=False):
    targets = settle_module.action_targets(env, action)
    measure = settle.needs_measurement(targets)
    before = _gripper_real(env) if measure else {}
    floors = _gripper_closed_floor(env) if measure else {}
    previous_step = int(env.take_action_cnt[ENV_IDX])
    env.take_action(action)
    executed = int(env.take_action_cnt[ENV_IDX]) - previous_step
    if executed <= 0:
        settle.interrupt("native")
        return
    report["executed"] += executed
    report["settle_steps" if added else "motion_executed"] += executed
    after = _gripper_real(env) if measure else {}
    settle.advance(targets, before, after, floors, added=added)


def _plan_keypose(TASK_ENV, request, config) -> tuple[list[dict], dict]:
    """Plan one motion request, reporting failures instead of raising.

    ``curobo_motion`` handles a planner that fails; this wrapper handles the
    planner module being unusable at all - an import error would otherwise
    repeat on every decision, so it is reported once and then disables the
    backend, leaving the episode to end on its zero-progress limit.
    """
    global _planner_disabled
    if _planner_disabled:
        return [], {"plan_status": "disabled"}
    try:
        planner = _sibling("curobo_motion")
        return planner.plan_actions(TASK_ENV, request, dict(config.get("curobo") or {}))
    except Exception as exc:  # noqa: BLE001 - never fail an eval on the motion path
        _planner_disabled = True
        print(f"[vlm_agent] cuRobo backend unavailable: {type(exc).__name__}: {exc}", flush=True)
        return [], {"plan_status": "Error", "planner_error": f"{type(exc).__name__}: {exc}"}


def _joint_module():
    """The cuRobo helper module, whose joint-space holds the executor uses; None when unusable."""
    try:
        return _sibling("curobo_motion")
    except Exception as exc:  # noqa: BLE001 - falls back to end-effector holds
        print(f"[vlm_agent] joint holds unavailable: {type(exc).__name__}: {exc}", flush=True)
        return None


def _run_sequence(TASK_ENV, envelope, config, capture, deadline, commanded_grippers, session, settle_module):
    """Execute one turn; the executor lives in main_route and gets this client's primitives."""
    main_route = _sibling("main_route")
    hooks = SimpleNamespace(
        execute_control=_execute_control,
        plan_keypose=lambda env, request: _plan_keypose(env, request, config),
        gripper_real=_gripper_real,
        gripper_closed_floor=_gripper_closed_floor,
        stop_reason=_control_stop_reason,
        ik_ok=_ik_ok,
        settle_module=settle_module,
        joint_module=_joint_module(),
    )
    report, stopped = main_route.run_sequence(TASK_ENV, envelope, config, hooks, session, deadline,
                                              capture.control_dt, commanded_grippers)
    turn = (envelope.get("plan") or {}).get("turn", "?")
    for result in report.get("command_results", []):
        print(f"[vlm_agent] turn {turn}: {result.get('command')} -> {'ok' if result.get('ok') else 'FAILED'}"
              f" ({result.get('steps_cost', 0)} steps){(' - ' + result['note']) if result.get('note') else ''}",
              flush=True)
    return report, stopped


def _warmup_planner(TASK_ENV) -> dict:
    try:
        return _sibling("curobo_motion").warmup(TASK_ENV)
    except Exception as exc:  # noqa: BLE001 - warmup is best effort
        return {"error": f"{type(exc).__name__}: {exc}"}


def _wants_calibration(config: dict) -> bool:
    """Whether this run needs head-camera calibration in the observation.

    The overlay is drawn in the policy server, which has the image but not the
    camera; the projection it needs is cheap to compute but not free, so it is
    only attached when something will actually use it.
    """
    aids = config.get("visual_aids") or {}
    return bool(aids.get("markers", True)) or bool(aids.get("grid", True))


def _gripper_real(TASK_ENV) -> dict:
    """Measured finger opening per arm, on the same 0..1 scale as the command.

    The ``<side>_ee_joint_state`` RoboDojo puts in the observation comes from
    ``control_manager.prev_control`` - the command last applied to the drive,
    not where the fingers are - so it reports a closing gripper the same way
    whether or not an object stopped it. This reads the articulation joint,
    which is what RoboDojo's own reward checks use
    (``env/reward_manager/func_parser.py`` ``is_all_gripper_open``). This is a
    joint-position measurement, not confirmation of contact or target grasp.
    """
    global _gripper_probe_disabled
    if _gripper_probe_disabled:
        return {}
    try:
        manager = TASK_ENV.robot_manager
        measured = {}
        for robot in manager.robot_list:
            if robot.type != "target" or getattr(robot, "ee_type", "gripper") != "gripper":
                continue
            values = manager.get_end_effector_real_val(robot, env_idx_list=[ENV_IDX])[ENV_IDX]
            if values is None:
                continue
            value = float(values[0] if hasattr(values, "__len__") else values)
            low, high = (float(bound) for bound in robot.gripper_scale[:2])
            if not high > low:
                continue
            # Same normalisation as obs_manager, including the mirrored sign.
            span = (value - low) if robot.gripper_move.get("sign", 1) == 1 else (high - value)
            measured[robot.arm_name.split("_")[0]] = round(min(max(span / (high - low), 0.0), 1.0), 4)
        return measured
    except Exception as exc:  # noqa: BLE001 - a diagnostic must not fail the eval
        _gripper_probe_disabled = True
        print(f"[vlm_agent] gripper measurement disabled after error: "
              f"{type(exc).__name__}: {exc}", flush=True)
        return {}


def _gripper_closed_floor(TASK_ENV) -> dict:
    """Physical closed limit of the measured primary finger, in command units."""
    global _gripper_floor_disabled
    if _gripper_floor_disabled:
        return {}
    try:
        manager = TASK_ENV.robot_manager
        floors = {}
        for robot in manager.robot_list:
            if robot.type != "target" or getattr(robot, "ee_type", "gripper") != "gripper":
                continue
            key = manager.robot_key[manager.robot_list.index(robot)]
            limits = key.root_physx_view.get_dof_limits()[ENV_IDX][int(robot.gripper_joint_indices[0])]
            physical_low, physical_high = (float(value) for value in limits)
            command_low, command_high = (float(value) for value in robot.gripper_scale[:2])
            if (not all(math.isfinite(value) for value in (physical_low, physical_high, command_low, command_high))
                    or physical_high < physical_low or command_high <= command_low):
                raise ValueError("invalid physical or commanded gripper limits")
            # A reversed drive closes at the physical upper bound. Match the
            # primary joint and scale used by _gripper_real, retaining its units.
            span = ((physical_low - command_low) if robot.gripper_move.get("sign", 1) == 1
                    else (command_high - physical_high))
            floors[robot.arm_name.split("_")[0]] = min(max(span / (command_high - command_low), 0.0), 1.0)
        return floors
    except Exception as exc:  # noqa: BLE001 - unknown limits must remain unknown
        _gripper_floor_disabled = True
        print(f"[vlm_agent] gripper closed reference unavailable: {type(exc).__name__}: {exc}", flush=True)
        return {}


def _end_unsuccessful(env):
    # RoboDojo initializes success=True. A custom budget must finalize it
    # through the native reward check, otherwise early exits count as success.
    env.success[ENV_IDX] = False
    env.is_episode_end()


def _camera_calibration(env, names=("cam_head",)):
    """Intrinsics and pose of the cameras in ``names``, for the overlays drawn in the server.

    Wrist cameras move with the hand, so this is read every step.

    Best effort: the overlay is an aid, so a camera this environment does not
    expose costs the aid and one warning, never the episode.
    """
    global _calibration_disabled
    if _calibration_disabled:
        return {}
    try:
        return _read_calibration(env, names)
    except Exception as exc:  # noqa: BLE001 - an aid must not fail the eval
        _calibration_disabled = True
        print(f"[vlm_agent] camera calibration unavailable, drawing no overlay: "
              f"{type(exc).__name__}: {exc}", flush=True)
        return {}


def _read_calibration(env, names=("cam_head",)):
    manager = env.camera_manager
    result = {}
    for index, name in enumerate(manager.camera_names[ENV_IDX]):
        if name not in names:
            continue
        camera = manager.cameras[ENV_IDX][index]
        intrinsic = camera.get_intrinsics_matrix()
        if hasattr(intrinsic, "cpu"):
            intrinsic = intrinsic.cpu().numpy()
        extrinsic = manager.get_camera_extrinsics(index, ENV_IDX)
        # The policy uses environment-local coordinates. This policy runs env0;
        # read the origin explicitly so calibration remains correct off-origin.
        origin = env.env_origins[ENV_IDX]
        if hasattr(origin, "cpu"):
            origin = origin.cpu().numpy()
        result[name] = {"intrinsic_matrix": intrinsic.tolist(),
                        "extrinsic_matrix": extrinsic.tolist(),
                        "env_origin": list(map(float, origin))}
    return result


def eval_one_episode_batch(TASK_ENV, model_client):
    """Batched eval is unsupported: one VLM call per env would serialise anyway."""
    raise NotImplementedError(
        "vlm_agent does not support batched eval; keep eval_batch: false in deploy.yml"
    )


def _episode_meta(TASK_ENV) -> dict:
    return {
        "phase": "episode_start",
        "task_name": getattr(TASK_ENV, "task_name", None),
        "steps_used": int(TASK_ENV.take_action_cnt[ENV_IDX]),
        "control_dt_s": _sibling("recording").control_period(TASK_ENV),
    }


def _ik_ok(TASK_ENV, arm: str, pose) -> bool | None:
    """Whether the env-local wrist ``pose`` has a joint solution for ``arm``.

    Used to say why the planner failed: no solution means the target is out of
    reach with that orientation, a solution means the path is blocked. ``None``
    when the check cannot run - the answer is then simply unknown.
    """
    global _ik_check_disabled
    if _ik_check_disabled:
        return None
    try:
        robot_manager = TASK_ENV.robot_manager
        for robot in robot_manager.robot_list:
            if robot.type != "target" or robot.arm_name.split("_")[0] != arm:
                continue
            result = robot_manager.solve_ik(target_pose=[float(v) for v in pose], env_idx=ENV_IDX, robot=robot)
            return (result or {}).get("status") == "Success"
    except Exception as exc:  # noqa: BLE001 - a diagnostic must not fail the eval
        _ik_check_disabled = True
        print(f"[vlm_agent] IK check disabled after error: {type(exc).__name__}: {exc}", flush=True)
    return None
