def move_pair(left=None, right=None, grips=(1.0, 1.0), max_steps=30,
              max_delta=0.025, tolerance=0.002, min_steps=3, stall_steps=8):
    obs = get_observation()
    initial = obs['state']
    targets = [list(initial['left_ee_pose']) if left is None else list(left),
               list(initial['right_ee_pose']) if right is None else list(right)]
    best = 100.0
    stale = 0
    for i in range(max_steps):
        state = obs['state']
        action = {'left_ee_joint_state': [grips[0]], 'right_ee_joint_state': [grips[1]]}
        error = 0.0
        orient_error = 0.0
        for key, target in zip(['left_ee_pose', 'right_ee_pose'], targets):
            current = state[key]
            diff = np.array(target[:3]) - current[:3]
            dist = float(np.linalg.norm(diff))
            error = max(error, dist)
            orient_error = max(orient_error, 1.0 - abs(float(np.dot(current[3:], target[3:]))))
            command = list(target)
            if dist > max_delta:
                command[:3] = list(current[:3] + diff * (max_delta / dist))
            action[key] = command
        if i >= min_steps and error <= tolerance and orient_error <= 0.002:
            return {'observation': obs, 'steps': i, 'reason': 'reached', 'error': error}
        if error < best - 0.0005:
            best = error
            stale = 0
        else:
            stale += 1
        if stale >= stall_steps and i >= min_steps:
            return {'observation': obs, 'steps': i, 'reason': 'stalled', 'error': error}
        obs, reward, terminated, truncated, info = step(action)
        if terminated or truncated:
            return {'observation': obs, 'steps': i + 1, 'reason': 'ended', 'success': info.get('success', False)}
    return {'observation': obs, 'steps': max_steps, 'reason': 'budget'}
