def ee_translate(arm, xyz, max_steps=40, max_delta=0.004, tolerance=0.002):
    obs = get_observation()
    s = obs['state']
    lp = list(s['left_ee_pose'])
    rp = list(s['right_ee_pose'])
    if grip_targets[0] is None: grip_targets[0] = float(s['left_ee_joint_state'][0])
    if grip_targets[1] is None: grip_targets[1] = float(s['right_ee_joint_state'][0])
    lg = [grip_targets[0]]
    rg = [grip_targets[1]]
    key = arm + '_ee_pose'
    orientation = list(s[key][3:])
    stalled = 0
    previous = None
    for i in range(max_steps):
        current = obs['state'][key]
        delta = [float(xyz[j]) - float(current[j]) for j in range(3)]
        distance = sum(d*d for d in delta)**0.5
        if distance < tolerance: break
        scale = min(1.0, max_delta / distance)
        target = [float(current[j]) + scale*delta[j] for j in range(3)] + orientation
        if arm == 'left': lp = target
        else: rp = target
        obs, reward, terminated, truncated, info = step({'left_ee_pose': lp, 'right_ee_pose': rp, 'left_ee_joint_state': lg, 'right_ee_joint_state': rg})
        if terminated or truncated:
            print({'steps': i+1, 'done': True, 'reward': reward})
            return obs, True
        stalled = stalled + 1 if previous is not None and abs(previous-distance) < 0.0001 else 0
        previous = distance
        if stalled >= 6: break
    print({'distance_remaining': sum((float(obs['state'][key][j])-float(xyz[j]))**2 for j in range(3))**0.5, 'steps_cap': max_steps})
    return obs, False
