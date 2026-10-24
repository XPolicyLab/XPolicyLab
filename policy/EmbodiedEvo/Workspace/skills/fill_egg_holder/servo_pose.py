def servo_pose(side, target, grip=None, max_steps=30, tolerance=0.004, min_steps=6):
    obs = get_observation()
    s = obs['state']
    action = {k: list(s[k]) for k in ['left_ee_pose', 'right_ee_pose', 'left_ee_joint_state', 'right_ee_joint_state']}
    action[side+'_ee_pose'] = list(target)
    if grip is not None:
        action[side+'_ee_joint_state'] = [grip]
    best = 100.0
    stagnant = 0
    for i in range(max_steps):
        obs, reward, terminated, truncated, info = step(action)
        actual = obs['state'][side+'_ee_pose']
        error = float(np.linalg.norm(actual[:3]-np.array(target[:3])))
        qerror = min(float(np.linalg.norm(actual[3:]-np.array(target[3:]))), float(np.linalg.norm(actual[3:]+np.array(target[3:]))))
        metric = error + 0.1*qerror
        if metric < best-0.0005:
            best = metric
            stagnant = 0
        else:
            stagnant += 1
        if terminated or truncated:
            break
        if i+1 >= min_steps and (error < tolerance and qerror < 0.04):
            break
        if stagnant >= 12:
            break
    print(side, 'steps', i+1, 'error', error, 'qerror', qerror, 'pose', actual, 'success', info.get('success', False), 'ended', terminated or truncated)
    return obs, terminated or truncated
