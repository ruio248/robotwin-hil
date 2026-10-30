"""Conservative privileged-state triage for handover_block HIL recovery.

This module selects a *candidate* expert suffix from observed physics state.
It does not execute motions and must not be used to label a rescue successful;
that requires the original task's ``check_success`` after expert control.
"""

from __future__ import annotations

import math
from typing import Any, Iterator


WORKSPACE = {"x": (-0.40, 0.40), "y": (-0.20, 0.43), "z": (0.74, 1.25)}
SETTLED_DISPLACEMENT_M = 0.025
GRASP_DISTANCE_M = 0.17
SOURCE_UNHELD_DISPLACEMENT_M = 0.006


def source_grasp_stage1_window(snapshot: dict[str, Any], next_action: Any = None,
                               initial_box_p: Any = None) -> dict[str, Any]:
    """Left-hand grasp stage, with a pre-action distant-close guard."""
    box = _finite_xyz(snapshot.get("box_p"))
    if box is None:
        return {"phase": "invalid_state", "reason": "invalid_box_pose"}
    if any(not (WORKSPACE[axis][0] <= value <= WORKSPACE[axis][1])
           for axis, value in zip(("x", "y", "z"), box)):
        return {"phase": "outside_window", "reason": "box_outside_workspace"}
    upright = _block_long_axis_vertical_component(snapshot.get("box_q"))
    if upright is None or upright < 0.75:
        return {"phase": "outside_window", "reason": "box_not_upright"}
    grippers = snapshot.get("gripper") or {}
    contacts = snapshot.get("gripper_box_contact") or {}
    left_closed = bool((grippers.get("left") or {}).get("closed"))
    if left_closed and contacts.get("left"):
        return {"phase": "stage_complete"}
    try:
        distance = float((snapshot.get("ee_to_box") or {})["left"])
    except (KeyError, TypeError, ValueError):
        return {"phase": "invalid_state", "reason": "missing_source_distance"}
    if not math.isfinite(distance):
        return {"phase": "invalid_state", "reason": "invalid_source_distance"}
    initial_box = _finite_xyz(initial_box_p) if initial_box_p is not None else None
    if initial_box is not None:
        displacement = math.dist(box, initial_box)
        # Trigger while the box has only started to move. The existing expert
        # classifier still gets the final say on whether it is safe to grasp.
        if (displacement >= SOURCE_UNHELD_DISPLACEMENT_M and not left_closed
                and distance > GRASP_DISTANCE_M):
            return {"phase": "intervene", "reason": "open_gripper_pushing_box",
                    "displacement_m": displacement, "ee_to_box": distance}
    if upright < 0.90:
        return {"phase": "intervene", "reason": "box_tilting_before_grasp",
                "uprightness": upright}
    if left_closed and distance > GRASP_DISTANCE_M:
        return {"phase": "intervene", "reason": "source_closed_without_contact",
                "ee_to_box": distance}
    if next_action is not None:
        try:
            action = [float(v) for v in next_action]
        except (TypeError, ValueError):
            return {"phase": "invalid_action", "reason": "nonfinite_or_wrong_action_dimension"}
        if len(action) != 14 or not all(math.isfinite(v) for v in action):
            return {"phase": "invalid_action", "reason": "nonfinite_or_wrong_action_dimension"}
        if action[6] < 0.2 and distance > GRASP_DISTANCE_M:
            return {"phase": "intervene", "reason": "source_close_while_too_far",
                    "ee_to_box": distance, "proposed_left_gripper": action[6]}
    return {"phase": "safe_window", "reason": "source_grasp_pending"}


def transfer_stage4_window(snapshot: dict[str, Any], next_action: Any = None) -> dict[str, Any]:
    """State-based receiver-grasp window with a pre-action source-release guard.

    The absolute-joint command stores the left gripper at index 6. RoboTwin's
    left gripper is closed only below 0.2. Contacts, not proximity alone, are
    required for this single-stage diagnostic's safe entry and completion.
    """
    box = _finite_xyz(snapshot.get("box_p"))
    if box is None:
        return {"phase": "invalid_state", "reason": "invalid_box_pose"}
    if any(not (WORKSPACE[axis][0] <= value <= WORKSPACE[axis][1])
           for axis, value in zip(("x", "y", "z"), box)):
        return {"phase": "outside_window", "reason": "box_outside_workspace"}
    upright = _block_long_axis_vertical_component(snapshot.get("box_q"))
    if upright is None or upright < 0.75:
        return {"phase": "outside_window", "reason": "box_not_upright"}
    grippers = snapshot.get("gripper") or {}
    contacts = snapshot.get("gripper_box_contact") or {}
    left = bool((grippers.get("left") or {}).get("closed") and contacts.get("left"))
    right = bool((grippers.get("right") or {}).get("closed") and contacts.get("right"))
    if right:
        return {"phase": "stage_complete", "both_holding": left}
    if not left:
        return {"phase": "outside_window", "reason": "source_not_holding"}
    if next_action is not None:
        try:
            action = [float(v) for v in next_action]
        except (TypeError, ValueError):
            return {"phase": "invalid_action", "reason": "nonfinite_or_wrong_action_dimension"}
        if len(action) != 14 or not all(math.isfinite(v) for v in action):
            return {"phase": "invalid_action", "reason": "nonfinite_or_wrong_action_dimension"}
        if action[6] >= 0.2:
            return {"phase": "intervene", "reason": "source_release_before_receiver_grasp",
                    "proposed_left_gripper": action[6]}
    return {"phase": "safe_window", "reason": "source_holds_receiver_not_yet_attached"}


def placement_stage6_window(snapshot: dict[str, Any], next_action: Any = None) -> dict[str, Any]:
    """Right-hand placement window; intercept release far from the target.

    The box center is about 0.10 m above its lower functional point in this
    task. XY and height bounds are preliminary safety guards, not a substitute
    for the original task success check after the command is executed.
    """
    box = _finite_xyz(snapshot.get("box_p"))
    target = _finite_xyz(snapshot.get("target_p"))
    if box is None or target is None:
        return {"phase": "invalid_state", "reason": "invalid_box_or_target_pose"}
    if snapshot.get("task_success") is True:
        return {"phase": "stage_complete"}
    if any(not (WORKSPACE[axis][0] <= value <= WORKSPACE[axis][1])
           for axis, value in zip(("x", "y", "z"), box)):
        return {"phase": "outside_window", "reason": "box_outside_workspace"}
    xy = math.dist(box[:2], target[:2])
    height_error = abs(box[2] - (target[2] + 0.10))
    near_target = xy <= 0.05 and height_error <= 0.07
    grippers = snapshot.get("gripper") or {}
    contacts = snapshot.get("gripper_box_contact") or {}
    right_holds = bool((grippers.get("right") or {}).get("closed") and contacts.get("right"))
    if not right_holds and near_target:
        return {"phase": "release_in_progress", "reason": "released_near_target"}
    if not right_holds:
        return {"phase": "outside_window", "reason": "receiver_not_holding"}
    if next_action is not None:
        try:
            action = [float(v) for v in next_action]
        except (TypeError, ValueError):
            return {"phase": "invalid_action", "reason": "nonfinite_or_wrong_action_dimension"}
        if len(action) != 14 or not all(math.isfinite(v) for v in action):
            return {"phase": "invalid_action", "reason": "nonfinite_or_wrong_action_dimension"}
        if action[13] >= 0.2:
            if not near_target:
                return {"phase": "intervene", "reason": "receiver_release_before_target",
                        "proposed_right_gripper": action[13],
                        "box_to_target_xy": xy, "box_center_height_error": height_error}
            return {"phase": "release_in_progress", "reason": "release_command_near_target"}
    return {"phase": "safe_window", "reason": "receiver_holds_before_placement"}


def handover_snapshot(task_env: Any, policy_steps: int) -> dict[str, Any]:
    """Capture live handover state for diagnosis and HIL stage selection.

    This privileged state is never supplied to the policy or used to prefilter
    evaluation seeds. A missing/non-finite pose is an infrastructure error,
    not evidence that the policy failed.
    """
    box = task_env.box
    box_p = _finite_xyz(box.get_pose().p)
    target_p = _finite_xyz(task_env.target_box.get_functional_point(1, "pose").p)
    if box_p is None or target_p is None:
        raise ValueError("missing or non-finite handover box/target position")
    try:
        box_q = tuple(float(value) for value in box.get_pose().q)
    except (TypeError, ValueError) as exc:
        raise ValueError("invalid handover box orientation") from exc
    if len(box_q) != 4 or not all(math.isfinite(value) for value in box_q):
        raise ValueError("missing or non-finite handover box orientation")
    ee_p = {}
    for side in ("left", "right"):
        ee_p[side] = _finite_xyz(task_env.get_arm_pose(side)[:3])
        if ee_p[side] is None:
            raise ValueError(f"missing or non-finite {side} end-effector position")
    gripper = {
        side: {
            "open": bool(getattr(task_env, f"is_{side}_gripper_open")()),
            "closed": bool(getattr(task_env, f"is_{side}_gripper_close")()),
        }
        for side in ("left", "right")
    }
    gripper_links = {}
    for side in ("left", "right"):
        names = set(getattr(task_env.robot, f"{side}_fix_gripper_name", []) or [])
        for item in getattr(task_env.robot, f"{side}_gripper", []) or []:
            if item is not None:
                try:
                    names.add(item[0].child_link.get_name())
                except (AttributeError, IndexError, TypeError):
                    pass
        gripper_links[side] = names
    contacts = {"left": False, "right": False}
    box_name = box.get_name()
    for contact in task_env.scene.get_contacts():
        try:
            names = {contact.bodies[0].entity.name, contact.bodies[1].entity.name}
        except (AttributeError, IndexError):
            continue
        if box_name in names:
            for side in contacts:
                contacts[side] |= bool(names & gripper_links[side])
    return {
        "policy_steps": policy_steps,
        "box_p": list(box_p),
        "box_q": list(box_q),
        "target_p": list(target_p),
        "box_to_target_xy": math.dist(box_p[:2], target_p[:2]),
        "ee_p": {side: list(point) for side, point in ee_p.items()},
        "ee_to_box": {side: math.dist(point, box_p) for side, point in ee_p.items()},
        "gripper": gripper,
        "gripper_box_contact": contacts,
        "task_success": bool(task_env.check_success()),
    }


def _finite_xyz(value: Any) -> tuple[float, float, float] | None:
    try:
        xyz = tuple(float(x) for x in value)
    except (TypeError, ValueError):
        return None
    if len(xyz) != 3 or not all(math.isfinite(x) for x in xyz):
        return None
    return xyz


def _block_long_axis_vertical_component(value: Any) -> float | None:
    """Return |world z component| of the box's local long (z) axis."""
    try:
        quaternion = tuple(float(x) for x in value)
    except (TypeError, ValueError):
        return None
    if len(quaternion) != 4 or not all(math.isfinite(x) for x in quaternion):
        return None
    norm_sq = sum(x * x for x in quaternion)
    if norm_sq < 1e-8:
        return None
    _, x, y, _ = (component / math.sqrt(norm_sq) for component in quaternion)
    return abs(1.0 - 2.0 * (x * x + y * y))


def classify_handover_state(
    current: dict[str, Any], previous: dict[str, Any] | None = None,
) -> dict[str, Any]:
    """Infer a recovery *entry stage* from a chunk-boundary trace snapshot.

    A closed gripper needs contact or close proximity to count as holding.
    For an unheld block, a second snapshot is required to avoid grasping a
    falling object. Ambiguous, unreachable, or non-finite states are rejected.
    Thresholds are conservative initial gates, not calibrated success claims.
    """
    box = _finite_xyz(current.get("box_p"))
    if box is None:
        return {"ready": False, "branch": "unknown", "reason": "invalid_box_pose"}
    if any(not (WORKSPACE[axis][0] <= value <= WORKSPACE[axis][1])
           for axis, value in zip(("x", "y", "z"), box)):
        return {"ready": False, "branch": "unrecoverable", "reason": "box_outside_workspace"}
    if current.get("task_success") is True:
        return {"ready": False, "branch": "done", "reason": "already_successful"}

    grippers = current.get("gripper") or {}
    contacts = current.get("gripper_box_contact") or {}
    distances = current.get("ee_to_box") or {}
    held: dict[str, bool] = {}
    for side in ("left", "right"):
        gripper = grippers.get(side) or {}
        if not isinstance(gripper.get("closed"), bool) or not isinstance(contacts.get(side), bool):
            return {"ready": False, "branch": "unknown", "reason": f"missing_{side}_grasp_signal"}
        try:
            distance = float(distances[side])
        except (KeyError, TypeError, ValueError):
            return {"ready": False, "branch": "unknown", "reason": f"missing_{side}_distance"}
        if not math.isfinite(distance):
            return {"ready": False, "branch": "unknown", "reason": f"invalid_{side}_distance"}
        held[side] = bool(gripper["closed"] and
                          (contacts[side] or distance <= GRASP_DISTANCE_M))

    if held["left"] and held["right"]:
        return {"ready": True, "stage_id": 5, "branch": "release_source", "holds": held}
    if held["right"]:
        return {"ready": True, "stage_id": 6, "branch": "receiver_place", "holds": held}
    if held["left"]:
        return {"ready": True, "stage_id": 3, "branch": "resume_handover", "holds": held}

    if previous is None:
        return {"ready": False, "branch": "wait_for_settle", "reason": "no_previous_pose", "holds": held}
    previous_box = _finite_xyz(previous.get("box_p"))
    if previous_box is None:
        return {"ready": False, "branch": "unknown", "reason": "invalid_previous_pose", "holds": held}
    displacement = math.dist(box, previous_box)
    if displacement > SETTLED_DISPLACEMENT_M:
        return {"ready": False, "branch": "wait_for_settle", "reason": "box_still_moving",
                "displacement_m": displacement, "holds": held}
    uprightness = _block_long_axis_vertical_component(current.get("box_q"))
    if uprightness is None:
        return {"ready": False, "branch": "unknown", "reason": "missing_or_invalid_box_orientation",
                "displacement_m": displacement, "holds": held}
    # The task's stock grasp plan assumes the long block is upright. Two
    # live dropped-state probes with the block lying on its side both failed
    # that plan, including one after retracting both arms. Do not issue the
    # same automatic grasp until a specialized side-lying recovery is tested.
    if uprightness < 0.75:
        return {"ready": False, "branch": "unknown", "reason": "fallen_sideways_requires_specialized_recovery",
                "displacement_m": displacement, "uprightness": uprightness, "holds": held}
    # The published task starts with the left arm grasping a block on the
    # negative-x side. A dropped block on the target side needs a separate
    # receiver-grasp plan rather than forcing the left arm across the scene.
    if box[0] > 0.05:
        return {"ready": False, "branch": "unknown", "reason": "right_side_unheld_requires_validation",
                "displacement_m": displacement, "holds": held}
    return {"ready": True, "stage_id": 1, "branch": "restart_source_grasp",
            "displacement_m": displacement, "holds": held}


def _arm_holds_box(task_env: Any, side: str) -> bool:
    """Recheck a grasp after a scripted action using live physics state."""
    if not getattr(task_env, f"is_{side}_gripper_close")():
        return False
    box_name = task_env.box.get_name()
    gripper_names = set(getattr(task_env.robot, f"{side}_fix_gripper_name", []) or [])
    for item in getattr(task_env.robot, f"{side}_gripper", []) or []:
        if item is not None:
            try:
                gripper_names.add(item[0].child_link.get_name())
            except (AttributeError, IndexError, TypeError):
                pass
    for contact in task_env.scene.get_contacts():
        try:
            names = {contact.bodies[0].entity.name, contact.bodies[1].entity.name}
        except (AttributeError, IndexError):
            continue
        if box_name in names and names & gripper_names:
            return True
    ee = _finite_xyz(task_env.get_arm_pose(side)[:3])
    box = _finite_xyz(task_env.box.get_pose().p)
    return bool(ee is not None and box is not None and
                math.dist(ee, box) <= GRASP_DISTANCE_M)


def iter_expert_suffix(task_env: Any, decision: dict[str, Any]) -> Iterator[dict[str, Any]]:
    """Run the live-state expert suffix one semantic action at a time.

    Each ``next()`` executes at most one scripted action and yields a stage
    event. A caller can hand control back to the policy without running the
    remaining suffix. The final event has ``phase == 'done'`` and contains
    the full result, including the original task's success check.
    """
    result: dict[str, Any] = {
        "initial_decision": decision, "executed_stage_ids": [],
        "plan_success": False, "success": False,
    }

    def done() -> dict[str, Any]:
        return {"phase": "done", "result": dict(result)}

    def progress(stage_id: int) -> dict[str, Any]:
        return {
            "phase": "stage", "stage_id": stage_id,
            "plan_success": bool(task_env.plan_success),
            "executed_stage_ids": list(result["executed_stage_ids"]),
        }

    if not decision.get("ready"):
        result["reason"] = decision.get("reason", "decision_not_ready")
        yield done()
        return
    branch = decision.get("branch")
    if branch not in {"restart_source_grasp", "resume_handover", "release_source", "receiver_place"}:
        result["reason"] = "unsupported_branch"
        yield done()
        return

    from envs.utils import ArmTag

    source, receiver = ArmTag("left"), ArmTag("right")
    task_env.plan_success = True

    def stage(stage_id: int, *actions: Any) -> bool:
        result["executed_stage_ids"].append(stage_id)
        if not task_env.plan_success:
            result.setdefault("reason", f"stage_{stage_id}_action_construction_failed")
            return False
        try:
            # Base_Task._take_picture embeds both fields in saved frames.
            # Set them before move(), which records the expert action path.
            task_env.current_control_source = "hil"
            task_env.current_stage_id = stage_id
            task_env.move(*actions)
        except Exception as exc:
            task_env.plan_success = False
            result["reason"] = f"stage_{stage_id}_exception: {exc!r}"
        if not task_env.plan_success and "reason" not in result:
            result["reason"] = f"stage_{stage_id}_planning_failed"
        return bool(task_env.plan_success)

    if branch == "restart_source_grasp":
        if not stage(1, task_env.open_gripper(source), task_env.open_gripper(receiver)):
            yield done()
            return
        yield progress(1)
        # A failed policy may leave both arms near the fallen block in poses
        # that obstruct a fresh grasp. Retract to the scripted start poses
        # before replanning from the block's *current* location.
        if not stage(1, task_env.back_to_origin(source), task_env.back_to_origin(receiver)):
            yield done()
            return
        yield progress(1)
        if not stage(1, task_env.grasp_actor(task_env.box, arm_tag=source,
                                             pre_grasp_dis=0.07, grasp_dis=0.0,
                                             contact_point_id=[0, 1, 2, 3])):
            yield done()
            return
        yield progress(1)
        if not _arm_holds_box(task_env, "left"):
            result["reason"] = "source_grasp_not_attached"
            yield done()
            return
        if not stage(2, task_env.move_by_displacement(source, z=0.10)):
            yield done()
            return
        yield progress(2)

    if branch in {"restart_source_grasp", "resume_handover"}:
        if not _arm_holds_box(task_env, "left"):
            result["reason"] = "source_not_holding"
            yield done()
            return
        if not stage(3, task_env.open_gripper(receiver)):
            yield done()
            return
        yield progress(3)
        if not stage(3, task_env.place_actor(
            task_env.box, target_pose=task_env.block_middle_pose,
            arm_tag=source, functional_point_id=0, pre_dis=0, dis=0,
            is_open=False, constrain="free",
        )):
            yield done()
            return
        yield progress(3)
        if not stage(4, task_env.grasp_actor(
            task_env.box, arm_tag=receiver, pre_grasp_dis=0.07,
            grasp_dis=0.0, contact_point_id=[4, 5, 6, 7],
        )):
            yield done()
            return
        yield progress(4)
        if not _arm_holds_box(task_env, "right"):
            result["reason"] = "receiver_grasp_not_attached"
            yield done()
            return

    if branch in {"restart_source_grasp", "resume_handover", "release_source"}:
        if not _arm_holds_box(task_env, "right"):
            result["reason"] = "receiver_not_holding"
            yield done()
            return
        if not stage(5, task_env.open_gripper(source)):
            yield done()
            return
        yield progress(5)
        if not stage(5, task_env.move_by_displacement(source, z=0.10, move_axis="arm")):
            yield done()
            return
        yield progress(5)

    if not _arm_holds_box(task_env, "right"):
        result["reason"] = "receiver_lost_box_before_placement"
        yield done()
        return
    if not stage(6, task_env.back_to_origin(source), task_env.place_actor(
        task_env.box,
        target_pose=task_env.target_box.get_functional_point(1, "pose"),
        arm_tag=receiver, functional_point_id=0, pre_dis=0.05, dis=0.0,
        constrain="align", pre_dis_axis="fp",
    )):
        yield done()
        return
    yield progress(6)
    result["plan_success"] = bool(task_env.plan_success)
    result["success"] = bool(task_env.check_success())
    task_env.eval_success = result["success"]
    if not result["success"]:
        result["reason"] = "original_task_success_check_failed"
    yield done()


def run_expert_suffix(task_env: Any, decision: dict[str, Any]) -> dict[str, Any]:
    """Consume the staged suffix for diagnostic one-shot recovery.

    Retains the original caller API; the incremental iterator is what an
    interactive HIL controller should drive at its stage boundaries.
    """
    final = None
    for event in iter_expert_suffix(task_env, decision):
        if event["phase"] == "done":
            final = event["result"]
    if final is None:
        raise RuntimeError("expert suffix ended without a final result")
    return final
