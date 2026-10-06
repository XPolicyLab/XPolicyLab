def move_ee(arm, target, gripper=0.0, max_steps=50, speed=0.008, tolerance=0.002):
    """Bounded measured-pose translation in metres; target is xyz + scalar-first quaternion."""
    obs = get_observation()
    other = 'right' if arm == 'left' else 'left'
    hold = np.array(obs['state'][other + '_ee_pose']).copy()
    hold_grip = obs['state'][other + '_ee_joint_state']
    settled = 0
    best_error = 1e9
    stalled = 0
    for n in range(max_steps):
        current = obs['state'][arm + '_ee_pose']
        delta = [target[i] - current[i] for i in range(3)]
        distance = sum(v*v for v in delta)**0.5
        scale = min(1.0, speed / max(distance, 0.000001))
        commanded = [current[i] + scale*delta[i] for i in range(3)] + list(target[3:])
        action = {arm+'_ee_pose': commanded, other+'_ee_pose': hold,
                  arm+'_ee_joint_state': [gripper], other+'_ee_joint_state':hold_grip}
        obs, reward, terminated, truncated, info = step(action)
        if terminated or truncated:
            return obs, {'steps':n+1, 'success':info.get('success',False), 'stopped':True}
        actual = obs['state'][arm+'_ee_pose']
        error = sum((target[i]-actual[i])**2 for i in range(3))**0.5
        if error < best_error - 0.0004:
            best_error = error
            stalled = 0
        else:
            stalled += 1
        if stalled >= 10:
            return obs, {'steps':n+1, 'position_error':error, 'stopped':False, 'stalled':True}
        quaternion_error = 1.0 - abs(sum(target[i]*actual[i] for i in range(3,7)))
        settled = settled + 1 if error < tolerance and quaternion_error < 0.002 else 0
        if settled >= 3:
            return obs, {'steps':n+1, 'position_error':error, 'stopped':False}
    return obs, {'steps':max_steps, 'position_error':error, 'stopped':False, 'budget_exhausted':True}
