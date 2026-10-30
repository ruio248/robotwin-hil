"""Conservative basket-lift suffix after a can is already stably in the basket.

This privileged stage triage is for HIL supervision only. It does not prefilter
policy evaluation seeds and never treats a scripted plan as task success.
"""

from __future__ import annotations

import math
from typing import Any, Callable, Iterator


# The task's *final* success threshold is 0.15 m. A can resting against the
# inner rim may be slightly farther before the basket is lifted and settles;
# keep a separate, provisional entry gate and still require the original final
# check after the expert suffix.
MAX_CAN_BASKET_L1_M = 0.20
MAX_GRASP_DISTANCE_M = 0.16


def _xyz(value: Any) -> tuple[float, float, float] | None:
    try:
        point = tuple(float(v) for v in value)
    except (TypeError, ValueError):
        return None
    return point if len(point) == 3 and all(math.isfinite(v) for v in point) else None


def _actor_gripper_contact(task_env: Any, actor: Any, side: str) -> bool:
    names = set(getattr(task_env.robot, f"{side}_fix_gripper_name", []) or [])
    for item in getattr(task_env.robot, f"{side}_gripper", []) or []:
        try:
            names.add(item[0].child_link.get_name())
        except (AttributeError, IndexError, TypeError):
            continue
    actor_name = actor.get_name()
    for contact in task_env.scene.get_contacts():
        try:
            pair = {contact.bodies[0].entity.name, contact.bodies[1].entity.name}
        except (AttributeError, IndexError):
            continue
        if actor_name in pair and bool(pair & names):
            return True
    return False


def basket_snapshot(task_env: Any, policy_steps: int) -> dict[str, Any]:
    source = str(task_env.arm_tag)
    if source not in ("left", "right"):
        raise ValueError(f"invalid can-arm assignment: {source}")
    receiver = "right" if source == "left" else "left"
    can = _xyz(task_env.can.get_pose().p)
    basket = _xyz(task_env.basket.get_pose().p)
    ee = _xyz(task_env.get_arm_pose(receiver)[:3])
    if any(point is None for point in (can, basket, ee)):
        raise ValueError("missing or non-finite can/basket/receiver pose")
    matrix = task_env.basket.get_pose().to_transformation_matrix()
    axis_z = float(matrix[2, 1])
    if not math.isfinite(axis_z):
        raise ValueError("invalid basket axis")
    return {
        "policy_steps": policy_steps,
        "source_arm": source, "receiver_arm": receiver,
        "can_p": list(can), "basket_p": list(basket),
        "basket_axis_z": axis_z,
        "basket_lift_m": basket[2] - float(task_env.start_height),
        "can_lift_m": can[2] - float(task_env.object_start_height),
        "can_basket_l1_m": sum(abs(a - b) for a, b in zip(can, basket)),
        "can_basket_contact": bool(task_env.check_actors_contact("071_can", "110_basket")),
        "can_table_contact": bool(task_env.check_actors_contact("071_can", "table")),
        "source_gripper_open": bool(getattr(task_env, f"is_{source}_gripper_open")()),
        "receiver_gripper_open": bool(getattr(task_env, f"is_{receiver}_gripper_open")()),
        "receiver_closed": bool(getattr(task_env, f"is_{receiver}_gripper_close")()),
        "receiver_basket_contact": _actor_gripper_contact(task_env, task_env.basket, receiver),
        "receiver_ee_to_basket_m": math.dist(ee, basket),
        "task_success": bool(task_env.check_success()),
    }


def classify_basket_state(current: dict[str, Any]) -> dict[str, Any]:
    can = _xyz(current.get("can_p"))
    basket = _xyz(current.get("basket_p"))
    source = current.get("source_arm")
    receiver = current.get("receiver_arm")
    if can is None or basket is None or (source, receiver) not in {
        ("left", "right"), ("right", "left"),
    }:
        return {"ready": False, "branch": "unknown", "reason": "invalid_scene_pose_or_arm"}
    if current.get("task_success") is True:
        return {"ready": False, "branch": "done", "reason": "already_successful"}
    if not (-0.45 <= basket[0] <= 0.45 and -0.25 <= basket[1] <= 0.40
            and 0.70 <= basket[2] <= 1.20):
        return {"ready": False, "branch": "unrecoverable", "reason": "basket_outside_workspace"}
    try:
        axis = float(current["basket_axis_z"])
        distance = float(current["can_basket_l1_m"])
        ee_distance = float(current["receiver_ee_to_basket_m"])
        lift = float(current["basket_lift_m"])
    except (KeyError, TypeError, ValueError):
        return {"ready": False, "branch": "unknown", "reason": "missing_physical_signal"}
    if not all(math.isfinite(value) for value in (axis, distance, ee_distance, lift)):
        return {"ready": False, "branch": "unknown", "reason": "invalid_physical_signal"}
    if axis <= 0.5:
        return {"ready": False, "branch": "unknown", "reason": "basket_tipped"}
    source_open = current.get("source_gripper_open")
    receiver_held = (current.get("receiver_closed") is True and
                     (current.get("receiver_basket_contact") is True or
                      ee_distance <= MAX_GRASP_DISTANCE_M))
    can_still_on_table = (current.get("can_table_contact") is True and
                          current.get("can_basket_contact") is False and
                          float(current.get("can_lift_m", math.inf)) <= 0.03)
    if can_still_on_table and source_open is True and receiver_held:
        return {"ready": True, "branch": "regrasp_place_can", "stage_id": 1,
                "source_arm": source, "receiver_arm": receiver}
    if (current.get("can_basket_contact") is not True
            or current.get("can_table_contact") is not False
            or distance >= MAX_CAN_BASKET_L1_M):
        return {"ready": False, "branch": "can_not_stably_in_basket",
                "reason": "can_placement_requires_separate_recovery"}
    held = (current.get("receiver_closed") is True and
            (current.get("receiver_basket_contact") is True or
             ee_distance <= MAX_GRASP_DISTANCE_M))
    if held:
        return {"ready": True, "branch": "lift_held_basket", "stage_id": 5,
                "source_arm": source, "receiver_arm": receiver}
    if lift > 0.02:
        return {"ready": False, "branch": "unknown", "reason": "raised_basket_unheld"}
    return {"ready": True, "branch": "grasp_then_lift_basket", "stage_id": 4,
            "source_arm": source, "receiver_arm": receiver}


def iter_basket_expert_suffix(task_env: Any, decision: dict[str, Any]) -> Iterator[dict[str, Any]]:
    result: dict[str, Any] = {"decision": decision, "executed_stage_ids": [],
                              "plan_success": False, "success": False}
    if not decision.get("ready") or decision.get("branch") not in {
        "regrasp_place_can", "grasp_then_lift_basket", "lift_held_basket",
    }:
        result["reason"] = decision.get("reason", "unsupported_branch")
        yield {"phase": "done", "result": dict(result)}
        return
    from envs.utils import ArmTag

    source = ArmTag(decision["source_arm"])
    receiver = ArmTag(decision["receiver_arm"])
    task_env.plan_success = True

    def stage(stage_id: int, build_motion: Callable[[], Any]) -> dict[str, Any]:
        task_env.current_stage_id = stage_id
        task_env.current_control_source = "hil"
        result["executed_stage_ids"].append(stage_id)
        try:
            motion = build_motion()
            if not task_env.plan_success:
                result["reason"] = f"stage_{stage_id}_action_construction_failed"
            else:
                task_env.move(motion)
        except Exception as exc:
            task_env.plan_success = False
            result["reason"] = f"stage_{stage_id}_exception: {exc!r}"
        return {"phase": "stage", "stage_id": stage_id,
                "plan_success": bool(task_env.plan_success),
                "executed_stage_ids": list(result["executed_stage_ids"])}

    if decision["branch"] == "regrasp_place_can":
        before_lower = basket_snapshot(task_env, policy_steps=0)
        lower_by = max(0.0, float(before_lower["basket_lift_m"])) + 0.01
        event = stage(4, lambda: task_env.move_by_displacement(
            arm_tag=receiver, z=-lower_by,
        ))
        yield event
        if not event["plan_success"]:
            result["reason"] = "basket_lowering_plan_failed"
            yield {"phase": "done", "result": dict(result)}
            return
        lowered = basket_snapshot(task_env, policy_steps=0)
        result["post_basket_lower_snapshot"] = lowered
        if (lowered["basket_lift_m"] > 0.025 or lowered["basket_axis_z"] <= 0.5
                or not lowered["receiver_closed"]):
            result["reason"] = "basket_not_stably_lowered"
            yield {"phase": "done", "result": dict(result)}
            return

        # Let the basket rest on the table before reaching the source arm into
        # it. Keeping the receiver hand attached made the can-placement plan
        # collide with a moving/held basket and can also pull the can back out.
        event = stage(4, lambda: task_env.open_gripper(arm_tag=receiver))
        yield event
        if not event["plan_success"]:
            result["reason"] = "basket_release_planning_failed"
            yield {"phase": "done", "result": dict(result)}
            return
        for _ in range(12):
            task_env.scene.step()
        released = basket_snapshot(task_env, policy_steps=0)
        result["post_basket_release_snapshot"] = released
        basket_shift = sum(abs(a - b) for a, b in zip(
            released["basket_p"], lowered["basket_p"],
        ))
        if (released["basket_lift_m"] > 0.025 or released["basket_axis_z"] <= 0.5
                or released["receiver_closed"] or basket_shift > 0.05):
            result["reason"] = "basket_not_stably_supported_after_release"
            yield {"phase": "done", "result": dict(result)}
            return

        event = stage(1, lambda: task_env.grasp_actor(
            task_env.can, arm_tag=source, pre_grasp_dis=0.05,
        ))
        yield event
        if not event["plan_success"]:
            result["reason"] = "can_regrasp_planning_failed"
            yield {"phase": "done", "result": dict(result)}
            return
        held_can = basket_snapshot(task_env, policy_steps=0)
        if not (not held_can["source_gripper_open"] and
                _actor_gripper_contact(task_env, task_env.can, source)):
            result["reason"] = "can_not_held_after_regrasp"
            result["post_regrasp_snapshot"] = held_can
            yield {"phase": "done", "result": dict(result)}
            return

        ee = task_env.get_arm_pose(arm_tag=source)
        points = [task_env.basket.get_functional_point(index) for index in (0, 1)]
        point_index = min(range(2), key=lambda index: math.dist(
            tuple(float(value) for value in points[index][:2]),
            tuple(float(value) for value in ee[:2]),
        ))
        # The task's two functional points sit above opposite basket sides.
        # A can target at either rim can make the held basket obstruct the
        # source arm and is less robust to residual basket motion; target the
        # midpoint of those calibrated points, retaining their shared frame.
        place_pose = [float(value) for value in points[point_index]]
        place_pose[:3] = [
            (float(points[0][axis]) + float(points[1][axis])) / 2.0
            for axis in range(3)
        ]
        place_pose[3:] = ([-1.0, 0.0, 0.0, 0.0] if source == "left"
                          else [0.05, 0.0, 0.0, 0.99])
        result["can_placement_geometry"] = {
            "source_ee_pose": [float(value) for value in ee],
            "basket_functional_points": [
                [float(value) for value in point] for point in points
            ],
            "nearest_functional_point_index": point_index,
            "selected_object_target": "basket_functional_point_midpoint",
            "direct_object_target": list(place_pose),
        }
        event = stage(2, lambda: task_env.place_actor(
            task_env.can, arm_tag=source, target_pose=place_pose,
            dis=0.02, is_open=False, constrain="free",
        ))
        yield event
        if not event["plan_success"]:
            # The task's built-in alternate passes an object target directly
            # to move_to_pose, which treats it as an end-effector pose and does
            # not compensate for the can-to-gripper transform. Instead compute
            # the compensated EE pose and verify the actual can placement.
            task_env.plan_success = True
            # Retry with the exact grasp-compensated end-effector pose, but
            # skip place_actor's extra pre-approach waypoint. That waypoint
            # was the failing plan in the observed rescue state; the single
            # final approach is still followed by a physical postcondition.
            fallback_pose = list(place_pose)
            fallback_final_ee = task_env.get_place_pose(
                task_env.can, arm_tag=source, target_pose=fallback_pose,
                constrain="free", pre_dis=0.02,
            )
            result["can_placement_geometry"]["fallback_object_target"] = list(fallback_pose)
            result["can_placement_geometry"]["fallback_final_ee_pose"] = [
                float(value) for value in fallback_final_ee
            ]
            for stage_id, motion in (
                (2, lambda: task_env.move_to_pose(
                    arm_tag=source, target_pose=fallback_final_ee,
                )),
                (2, lambda: task_env.move_by_displacement(arm_tag=source, z=-0.02)),
                (3, lambda: task_env.open_gripper(arm_tag=source)),
                (3, lambda: task_env.move_by_displacement(arm_tag=source, z=0.12)),
            ):
                fallback_event = stage(stage_id, motion)
                yield fallback_event
                if not fallback_event["plan_success"]:
                    result["reason"] = "alternate_can_placement_failed"
                    yield {"phase": "done", "result": dict(result)}
                    return
        else:
            for motion in (
                lambda: task_env.open_gripper(arm_tag=source),
                lambda: task_env.move_by_displacement(arm_tag=source, z=0.12),
            ):
                event = stage(3, motion)
                yield event
                if not event["plan_success"]:
                    result["reason"] = "can_release_or_retract_failed"
                    yield {"phase": "done", "result": dict(result)}
                    return
        for _ in range(12):
            task_env.scene.step()
        placed = basket_snapshot(task_env, policy_steps=0)
        decision = classify_basket_state(placed)
        result["post_can_placement_snapshot"] = placed
        result["post_can_placement_decision"] = decision
        if not decision.get("ready") or decision.get("branch") == "regrasp_place_can":
            result["reason"] = "can_not_stably_placed_in_basket"
            yield {"phase": "done", "result": dict(result)}
            return
        if placed["can_basket_l1_m"] >= 0.15 or placed["can_table_contact"]:
            result["reason"] = "can_placement_outside_original_success_threshold"
            yield {"phase": "done", "result": dict(result)}
            return
        if decision["branch"] == "grasp_then_lift_basket":
            result["reason"] = "receiver_lost_basket_after_can_placement"
            yield {"phase": "done", "result": dict(result)}
            return
        if decision["branch"] != "lift_held_basket":
            result["reason"] = "unexpected_post_placement_branch"
            yield {"phase": "done", "result": dict(result)}
            return

    if decision["branch"] == "regrasp_place_can":
        # The recursive state check above must transition to a normal lift branch.
        result["reason"] = "recovery_state_did_not_advance"
        yield {"phase": "done", "result": dict(result)}
        return
    if decision["branch"] == "lift_held_basket":
        event = stage(5, lambda: task_env.move_by_displacement(
            arm_tag=receiver, x=-0.02 if receiver == "left" else 0.02, z=0.05,
        ))
        yield event
        if not event["plan_success"]:
            task_env.plan_success = True
            event = stage(5, lambda: task_env.move_by_displacement(
                arm_tag=receiver, z=0.05,
            ))
            yield event
        result["plan_success"] = bool(task_env.plan_success)
        result["success"] = bool(task_env.plan_success and task_env.check_success())
        if not result["success"]:
            result["reason"] = "lift_plan_or_task_check_failed"
        yield {"phase": "done", "result": dict(result)}
        return

    if decision["branch"] == "grasp_then_lift_basket":
        initial = basket_snapshot(task_env, policy_steps=0)
        # Match the task's two documented continuations: after its alternate
        # can placement the source gripper is already open and the stock basket
        # grasp uses a 0.02 m pre-grasp; after the direct placement it uses 0.08.
        basket_pre_grasp = 0.02 if initial["source_gripper_open"] else 0.08
        source_retract = [lambda: task_env.back_to_origin(arm_tag=source)]
        if not initial["source_gripper_open"]:
            source_retract = [
                lambda: task_env.open_gripper(arm_tag=source),
                lambda: task_env.move_by_displacement(arm_tag=source, z=0.12),
                *source_retract,
            ]
        for motion in source_retract:
            event = stage(4, motion)
            yield event
            if not event["plan_success"]:
                yield {"phase": "done", "result": dict(result)}
                return
        after_retract = basket_snapshot(task_env, policy_steps=0)
        after_retract_decision = classify_basket_state(after_retract)
        if not after_retract_decision.get("ready"):
            result["reason"] = "can_left_basket_during_source_retract"
            result["post_source_retract_snapshot"] = after_retract
            result["post_source_retract_decision"] = after_retract_decision
            yield {"phase": "done", "result": dict(result)}
            return
        for motion in (
            lambda: task_env.grasp_actor(task_env.basket, arm_tag=receiver,
                                         pre_grasp_dis=basket_pre_grasp),
            lambda: task_env.close_gripper(arm_tag=receiver),
        ):
            event = stage(4, motion)
            yield event
            if not event["plan_success"]:
                yield {"phase": "done", "result": dict(result)}
                return
        snapshot = basket_snapshot(task_env, policy_steps=0)
        if not (snapshot["receiver_closed"] and
                (snapshot["receiver_basket_contact"] or
                 snapshot["receiver_ee_to_basket_m"] <= MAX_GRASP_DISTANCE_M)):
            result["reason"] = "basket_not_held_after_grasp"
            yield {"phase": "done", "result": dict(result)}
            return
    event = stage(5, lambda: task_env.move_by_displacement(
        arm_tag=receiver, x=-0.02 if receiver == "left" else 0.02, z=0.05,
    ))
    yield event
    result["plan_success"] = bool(task_env.plan_success)
    result["success"] = bool(task_env.plan_success and task_env.check_success())
    if not result["success"]:
        result["reason"] = "lift_plan_or_task_check_failed"
    yield {"phase": "done", "result": dict(result)}
