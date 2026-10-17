def pose_path(arm, target, lg, rg, waypoints=20, steps_per_waypoint=2, max_actions=60, position_limit=0.05, quaternion_min=0.97):
    obs = get_observation()
    s = obs['state']
    key = arm + '_ee_pose'
    start = np.array(s[key])
    goal = np.array(target)
    if np.dot(start[3:], goal[3:]) < 0: goal[3:] = -goal[3:]
    left = s['left_ee_pose']
    right = s['right_ee_pose']
    used = 0
    stop = False
    lagged = 0
    for i in range(1,waypoints+1):
        fraction = i / waypoints
        p = (1-fraction)*start + fraction*goal
        p[3:] = p[3:] / np.linalg.norm(p[3:])
        if arm == 'left': left = p
        else: right = p
        for j in range(steps_per_waypoint):
            if used >= max_actions:
                stop = True
                break
            obs, reward, terminated, truncated, info = step({'left_ee_pose':left,'right_ee_pose':right,'left_ee_joint_state':[lg],'right_ee_joint_state':[rg]})
            used += 1
            if terminated or truncated:
                stop = True
                break
        actual = obs['state'][key]
        if np.linalg.norm(p[:3]-actual[:3]) > position_limit or abs(np.dot(p[3:],actual[3:])) < quaternion_min:
            lagged += 1
        else:
            lagged = 0
        if lagged >= 3:
            print('tracking_guard_stop', i)
            stop = True
        if stop: break
    print('path', used, obs['state'][key], 'position_error', np.linalg.norm(goal[:3]-obs['state'][key][:3]), 'quaternion_dot',abs(np.dot(goal[3:],obs['state'][key][3:])))
    return obs
