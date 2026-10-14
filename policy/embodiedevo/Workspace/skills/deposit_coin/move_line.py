def move_line(arm, target_xyz, grip, max_steps=40, increment=0.005, tolerance=0.001, stall_steps=5):
    if max_steps < 1 or increment <= 0 or tolerance <= 0:
        raise ValueError('positive step budget, increment, and tolerance are required')
    obs = get_observation()
    s = obs['state']
    action = {k: list(s[k]) for k in ['left_ee_pose', 'right_ee_pose', 'left_ee_joint_state', 'right_ee_joint_state']}
    key = arm + '_ee_pose'
    grip_commands[arm] = grip
    for side in grip_commands:
        action[side + '_ee_joint_state'] = [grip_commands[side]]
    orientation = list(s[key][3:])
    best = 1000.0
    stale = 0
    used = 0
    terminated = False
    truncated = False
    info = {}
    for i in range(max_steps):
        current = obs['state'][key]
        error = [target_xyz[j] - float(current[j]) for j in range(3)]
        distance = sum(e * e for e in error) ** 0.5
        if distance <= tolerance:
            break
        scale = min(1.0, increment / distance)
        action[key] = [float(current[j]) + scale * error[j] for j in range(3)] + orientation
        obs, reward, terminated, truncated, info = step(action)
        used += 1
        if terminated or truncated:
            break
        if distance < best - min(0.0001, tolerance * 0.1):
            best = distance
            stale = 0
        else:
            stale += 1
            if stale >= stall_steps:
                print('line_stalled', distance)
                break
    print('line', used, list(obs['state'][key]), info)
    return obs, terminated, truncated, info
