def servo_ee(arm, target, opening, max_steps, position_tolerance=0.003,
             settle_steps=3, stall_steps=8):
    # Move one arm using pose feedback, preserving the other arm's pose/opening.
    obs = get_observation()
    other = 'left' if arm == 'right' else 'right'
    fixed = obs['state'][other + '_ee_pose'].copy()
    fixed_open = list(obs['state'][other + '_ee_joint_state'])
    previous = obs['state'][arm + '_ee_pose'][:3].copy()
    stable = 0
    stalled = 0
    for used in range(max_steps):
        command = {
            arm + '_ee_pose': list(target),
            other + '_ee_pose': fixed.copy(),
            arm + '_ee_joint_state': [opening],
            other + '_ee_joint_state': list(fixed_open),
        }
        obs, reward, terminated, truncated, info = step(command)
        current = obs['state'][arm + '_ee_pose']
        error = np.linalg.norm(current[:3] - np.array(target[:3]))
        alignment = abs(float(np.dot(current[3:], np.array(target[3:]))))
        grip_error = abs(obs['state'][arm + '_ee_joint_state'][0] - opening)
        stable = stable + 1 if error < position_tolerance and alignment > 0.999 and grip_error < 0.04 else 0
        stalled = stalled + 1 if np.linalg.norm(current[:3] - previous) < 0.0002 else 0
        previous = current[:3].copy()
        if terminated or truncated:
            return obs, used + 1, 'ended'
        if stable >= settle_steps:
            return obs, used + 1, 'reached'
        if stalled >= stall_steps and error > position_tolerance:
            return obs, used + 1, 'stalled'
    return obs, max_steps, 'budget'
