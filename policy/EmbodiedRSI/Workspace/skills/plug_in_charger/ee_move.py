def ee_move(arm, target, grip, max_steps, pos_tol=0.001, quat_tol=0.01, min_steps=3, stall_steps=12):
    obs = get_observation()
    other = 'right' if arm == 'left' else 'left'
    hold = obs['state'][other + '_ee_pose'][:]
    other_grip = obs['state'][other + '_ee_joint_state'][:]
    stable = 0
    stagnant = 0
    best = 1000.0
    reward = 0.0
    terminated = False
    truncated = False
    info = {}
    reason = 'budget'
    used = 0
    for i in range(max_steps):
        action = {arm + '_ee_pose': target, other + '_ee_pose': hold,
                  arm + '_ee_joint_state': [grip], other + '_ee_joint_state': other_grip}
        obs, reward, terminated, truncated, info = step(action)
        used += 1
        if terminated or truncated:
            reason = 'episode_end'
            break
        pose = obs['state'][arm + '_ee_pose']
        pe = sum((pose[j] - target[j]) ** 2 for j in range(3)) ** 0.5
        qe = min(sum((pose[j] - target[j]) ** 2 for j in range(3, 7)),
                 sum((pose[j] + target[j]) ** 2 for j in range(3, 7))) ** 0.5
        error = pe + 0.1 * qe
        if error < best - 0.0001:
            best = error
            stagnant = 0
        else:
            stagnant += 1
        stable = stable + 1 if pe <= pos_tol and qe <= quat_tol else 0
        if used >= min_steps and stable >= 3:
            reason = 'reached'
            break
        if used >= min_steps and stagnant >= stall_steps:
            reason = 'stalled'
            break
    print({'move_reason': reason, 'steps': used, 'pose': obs['state'][arm + '_ee_pose']})
    return obs, reward, terminated, truncated, info
