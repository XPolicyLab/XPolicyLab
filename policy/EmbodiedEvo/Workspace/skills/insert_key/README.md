# Reusable robot-control helpers

These helpers were developed with the dual ARX X5, absolute world EE poses, and scalar-first quaternions. They have no top-level robot actions. Load selected Python files with `python scripts/env.py exec submission/solution.py --include skills/ee_stage.py ...`.

Before the first helper call and after every reset, initialise `grip_targets = [1.0, 1.0]` or the explicitly desired commands. Do not initialise a loaded gripper from the returned state/action values: both reflected contact-dependent jaw positions in the experiments. `ee_stage(..., left_grip=0.0)` updates the persistent command list.

- `ee_stage.py`: short absolute pose or gripper stage, with measured convergence and stall checks.
- `ee_translate.py`: bounded translation at fixed orientation, useful for delicate carrying.
- `ee_rotate.py`: bounded free-space wrist rotation at fixed EE position.
- `ee_yaw_pivot.py`: yaw with translation compensation around an explicit world xy pivot.
- `guarded_descent.py`: downward motion guarded by jaw opening, tracking error, and lack of vertical progress.

All calls require a positive `max_steps` within the live native action allowance. The runner does not expose the shell budget query inside submitted Python, so allocate stage caps before submission using `env.py status`. Do not chain after terminal feedback. `ee_stage`, `ee_translate`, and `ee_rotate` return a boolean for terminal feedback only; failure to converge is reported in stdout and needs caller inspection before further stages. `ee_yaw_pivot` and `guarded_descent` also return true on their safety/contact guards, so that boolean means halt the current sequence.

These helpers generate and monitor robot motion. They do not estimate object poses, detect success, certify grasp retention, or constitute a solved insert-key policy. See the companion documents for evidence and limitations, and `lessons/README.md` for the experiment findings. Only this single Playground layout was tested.
