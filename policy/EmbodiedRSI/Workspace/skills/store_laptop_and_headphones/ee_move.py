def ee_move(arm, xyz, quat=None, grip=None, budget=35, tolerance=0.008, min_steps=7, stall_steps=6):
    obs = get_observation()
    if budget <= 0:
        return obs, 'budget', 0
    state = obs['state']
    pose = list(state[arm+'_ee_pose'])
    pose[:3] = list(xyz)
    if quat is not None:
        pose[3:] = list(quat)
    action = {k: list(state[k]) for k in ['left_ee_pose','right_ee_pose','left_ee_joint_state','right_ee_joint_state']}
    action[arm+'_ee_pose'] = pose
    if grip is not None:
        action[arm+'_ee_joint_state'] = [grip]
    previous = np.array(state[arm+'_ee_pose'][:3])
    stagnant = 0
    reason = 'budget'
    for i in range(budget):
        obs, reward, terminated, truncated, info = step(action)
        measured = obs['state'][arm+'_ee_pose']
        err = np.linalg.norm(np.array(measured[:3])-np.array(xyz))
        qerr = min(np.linalg.norm(np.array(measured[3:])-np.array(pose[3:])), np.linalg.norm(np.array(measured[3:])+np.array(pose[3:])))
        if terminated or truncated:
            reason = 'terminated' if terminated else 'truncated'
            break
        stagnant = stagnant + 1 if np.linalg.norm(np.array(measured[:3])-previous) < 0.0005 else 0
        previous = np.array(measured[:3])
        if i+1 >= min_steps and err < tolerance and qerr < 0.06:
            reason = 'reached'
            break
        if i+1 >= min_steps and stagnant >= stall_steps and (err >= tolerance or qerr >= 0.06):
            reason = 'stalled'
            break
    print(arm, reason, i+1, 'error', err, 'pose', obs['state'][arm+'_ee_pose'])
    return obs, reason, i+1
