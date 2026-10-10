def servo_pose(arm, target, grip, max_steps=40, position_tol=0.002, quaternion_tol=0.015, max_translation=0.018, settle_steps=4, stall_steps=12, direct=True):
    # Bounded EE feedback controller; callers initialize control_remaining after reset.
    global control_remaining, control_done
    obs = get_observation()
    other = 'left' if arm == 'right' else 'right'
    hold_pose = list(obs['state'][other+'_ee_pose'])
    hold_grip = list(obs['state'][other+'_ee_joint_state'])
    target = np.array(target)
    best = 1000.0
    stale = 0
    settled = 0
    used = 0
    for i in range(max_steps):
        if control_done or control_remaining <= 0:
            break
        current = np.array(obs['state'][arm+'_ee_pose'])
        goal_q = target[3:].copy()
        if np.dot(current[3:], goal_q) < 0:
            goal_q = -goal_q
        delta = target[:3] - current[:3]
        pos_error = float(np.linalg.norm(delta))
        quat_error = float(np.linalg.norm(goal_q-current[3:]))
        error = pos_error + 0.15*quat_error
        if error < best-0.0005:
            best=error
            stale=0
        else:
            stale += 1
        if pos_error < position_tol and quat_error < quaternion_tol:
            settled += 1
        else:
            settled = 0
        if settled >= settle_steps and used >= settle_steps:
            break
        if stale >= stall_steps and used >= settle_steps:
            break
        fraction = min(1.0, max_translation/max(pos_error,0.000001))
        p = current.copy()
        p[:3] = current[:3]+fraction*delta
        q_fraction = min(1.0,0.15/max(quat_error,0.000001))
        p[3:] = current[3:]*(1-q_fraction)+goal_q*q_fraction
        p[3:] = p[3:]/np.linalg.norm(p[3:])
        if direct:
            p = target.copy()
        action={other+'_ee_pose':hold_pose, other+'_ee_joint_state':hold_grip, arm+'_ee_pose':p, arm+'_ee_joint_state':[grip]}
        obs,reward,terminated,truncated,info=step(action)
        control_remaining-=1
        used+=1
        control_done=bool(terminated or truncated)
    actual=np.array(obs['state'][arm+'_ee_pose'])
    err=float(np.linalg.norm(actual[:3]-target[:3]))
    qerr=min(float(np.linalg.norm(actual[3:]-target[3:])),float(np.linalg.norm(actual[3:]+target[3:])))
    print('servo',arm,'used',used,'position',actual[:3],'error',err,'quaternion_error',qerr,'remaining',control_remaining,'done',control_done)
    return obs, err <= position_tol and qerr <= quaternion_tol
