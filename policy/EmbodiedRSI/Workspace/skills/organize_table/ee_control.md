# Bounded end-effector motion

`move_ee` accepts an arm name, absolute world XYZ in metres, scalar-first quaternion, normalized gripper command, and a maximum step budget. It holds the opposite arm at its measured pose, observes after every action, and stops after position and orientation convergence or termination. The caller must allocate `max_steps` within the current allowance and check returned termination flags before another stage. Use minimum hold steps for contact/gripper settling; pose convergence alone does not establish a grasp. It performs no collision avoidance and requires visually selected clear waypoints.

Evidence: observation 000002 reached right XYZ (0.25,-0.20,1.02), within 0.1 mm of target. Quaternion (0.5,-0.5,0.5,0.5) points the gripper downward with fingers across world X. This wrapper is being validated incrementally in the current scene; transfer is untested.

`linear_ee` advances along a Cartesian segment from the measured pose, with an explicit distance increment (default 4 mm per action). It maintains the opposite arm and selected grip. It checks native termination after every action. Set `max_steps` large enough for distance/increment: clipping the count increases the actual increment. Inspect the final pose and image; the function does not certify a grasp or force contact. Evidence 000013-000015: gradual descent, aligned close, and 10 cm lift retained the mouse in the jaws, unlike earlier abrupt and offset grasps.

`rotate_ee` uses normalized quaternion interpolation, flips the target sign to select the shorter quaternion path, holds the measured position, and stops on native termination. It is useful only when the swept volume is clear. A 16-action small tilt retained the flat-sided clock (000086), while a much larger rotation dropped the figurine despite 35 interpolation actions (000064). Rotation interpolation does not guarantee retention.

Important limitation: `linear_ee` and `rotate_ee` report the final pose but do not abort on tracking error. Callers must inspect the measured pose before any dependent contact stage. A missed forward waypoint followed by descent caused major object displacement in 000095. Do not chain stages through an unreachable target. `move_ee` has a lack-of-motion check, but its return flags describe native episode termination, not waypoint success.

All evidence is from this Playground scene. None of these helpers detect object pose, collision, grasp success, or task completion from images. Human/model review of no more than two current camera frames per iteration supplied that feedback.

`ee_target_reached` is a read-only guard for dependent stages. It reads the measured pose, checks Euclidean position error and sign-invariant quaternion dot product, and returns a boolean. Call it after a move and before descending or closing; a false result requires observation and replanning. Its tolerance check is derived from the reachable/unreachable pose evidence in 000003-000006 and 000095. The helper itself has not driven robot actions.

Final validation: these helpers supported the officially successful final attempt 000096-000100, with 764 native actions. The final safe order was clock, keyboard, mouse, figurine, then retreat/home. Success arrived during home interpolation before exact joint convergence. See `lessons/validated_outcome.md`.
