def return_to_joints(targets, action_budget, max_joint_change=0.06,
                     tolerance=0.005, settle_steps=5, stall_steps=20):
    """Move toward explicit stored joint targets with bounded measured feedback."""
    obs = get_observation()
    settled = 0
    stalled = 0
    best = 1000.0
    used = 0
    reason = 'budget'
    for i in range(action_budget):
        s = obs['state']
        error = 0.0
        action = {'left_ee_joint_state': [1.0], 'right_ee_joint_state': [1.0]}
        for arm in ['left', 'right']:
            key = arm + '_arm_joint_state'
            current = np.array(s[key])
            delta = np.array(targets[key]) - current
            error = max(error, float(np.max(np.abs(delta))))
            action[key] = current + np.clip(delta, -max_joint_change, max_joint_change)
        settled = settled + 1 if error < tolerance else 0
        if settled >= settle_steps:
            reason = 'reached'
            break
        if error < best - 0.0005:
            best = error
            stalled = 0
        else:
            stalled += 1
        if stalled >= stall_steps:
            reason = 'stalled'
            break
        obs, reward, terminated, truncated, info = step(action)
        used += 1
        if terminated or truncated:
            reason = 'terminated' if terminated else 'truncated'
            break
    print('return_to_joints', reason, 'steps', used, 'error', error)
    return obs, reason, used
