def dual_servo(left_target, right_target, left_grip, right_grip, max_steps=50, position_step=0.004, quaternion_step=0.02, min_steps=0):
    obs = get_observation()
    best = 100.0
    stale = 0
    for i in range(max_steps):
        action = {'left_ee_joint_state': [left_grip], 'right_ee_joint_state': [right_grip]}
        total_error = 0.0
        reached = True
        for arm, target in [('left', left_target), ('right', right_target)]:
            pose = list(obs['state'][arm + '_ee_pose'])
            delta = [target[j] - float(pose[j]) for j in range(3)]
            distance = sum(v*v for v in delta) ** 0.5
            sign = 1.0 if sum(float(pose[j])*target[j] for j in range(3,7)) >= 0 else -1.0
            qdelta = [sign*target[j+3] - float(pose[j+3]) for j in range(4)]
            qdistance = sum(v*v for v in qdelta) ** 0.5
            fraction = min(1.0, position_step/max(distance,0.000001), quaternion_step/max(qdistance,0.000001))
            q = [float(pose[j+3]) + fraction*qdelta[j] for j in range(4)]
            norm = sum(v*v for v in q) ** 0.5
            action[arm+'_ee_pose'] = [float(pose[j])+fraction*delta[j] for j in range(3)] + [v/norm for v in q]
            total_error += distance + qdistance
            reached = reached and distance < 0.002 and qdistance < 0.01
        if reached and i >= min_steps:
            return obs, i, 'reached'
        obs, reward, terminated, truncated, info = step(action)
        if terminated or truncated:
            return obs, i+1, 'episode_end'
        if total_error < best - 0.0003:
            best = total_error
            stale = 0
        else:
            stale += 1
        if stale >= max(12,min_steps+1):
            return obs, i+1, 'stalled'
    return obs, max_steps, 'budget'
