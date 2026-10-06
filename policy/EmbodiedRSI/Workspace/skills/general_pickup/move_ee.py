def move_ee(arm, target, gripper, max_steps, position_tolerance=0.004,
            quaternion_tolerance=0.002, stall_steps=4):
    obs = get_observation()
    state = obs['state']
    other = 'left' if arm == 'right' else 'right'
    hold_pose = list(state[other + '_ee_pose'])
    hold_grip = list(state[other + '_ee_joint_state'])
    previous = list(state[arm + '_ee_pose'])
    stagnant = 0
    result = {'steps': 0, 'reason': 'budget', 'success': False}
    for index in range(max_steps):
        action = {arm + '_ee_pose': list(target),
                  other + '_ee_pose': hold_pose,
                  arm + '_ee_joint_state': [gripper],
                  other + '_ee_joint_state': hold_grip}
        obs, reward, terminated, truncated, info = step(action)
        pose = list(obs['state'][arm + '_ee_pose'])
        error = sum((pose[j] - target[j]) ** 2 for j in range(3)) ** 0.5
        angle_error = 1.0 - abs(sum(pose[j] * target[j] for j in range(3, 7)))
        movement = sum((pose[j] - previous[j]) ** 2 for j in range(7)) ** 0.5
        result = {'steps': index + 1, 'reason': 'budget', 'success': bool(info.get('success', False)),
                  'position_error': error, 'quaternion_error': angle_error, 'pose': pose}
        if terminated or truncated:
            result['reason'] = 'terminated' if terminated else 'truncated'
            break
        if error <= position_tolerance and angle_error <= quaternion_tolerance:
            result['reason'] = 'reached'
            break
        stagnant = stagnant + 1 if movement < 0.0001 else 0
        if stagnant >= stall_steps:
            result['reason'] = 'stalled'
            break
        previous = pose
    return obs, result
