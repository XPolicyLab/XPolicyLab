def move_ee(arm, target, grip, max_steps, min_steps=3, tolerance=0.002, max_delta=0.025):
    """Move one arm toward an absolute world pose and hold the other measured arm."""
    obs = get_observation()
    other = 'right' if arm == 'left' else 'left'
    fixed_pose = list(obs['state'][other + '_ee_pose'])
    fixed_grip = list(obs['state'][other + '_ee_joint_state'])
    previous_error = None
    stalled = 0
    for count in range(max_steps):
        current = obs['state'][arm + '_ee_pose']
        error = sum((target[j] - current[j]) ** 2 for j in range(3)) ** 0.5
        ratio = min(1.0, max_delta / max(error, 1e-9))
        command = [current[j] + ratio * (target[j] - current[j]) for j in range(3)] + list(target[3:])
        obs, reward, terminated, truncated, info = step({
            arm + '_ee_pose': command,
            other + '_ee_pose': fixed_pose,
            arm + '_ee_joint_state': [grip],
            other + '_ee_joint_state': fixed_grip})
        current = obs['state'][arm + '_ee_pose']
        new_error = sum((target[j] - current[j]) ** 2 for j in range(3)) ** 0.5
        rotation_error = min(sum((target[j] - current[j]) ** 2 for j in range(3, 7)),
                             sum((target[j] + current[j]) ** 2 for j in range(3, 7))) ** 0.5
        if terminated or truncated or reward:
            return obs, count + 1, 'episode_end'
        if count + 1 >= min_steps and new_error < tolerance and rotation_error < 0.02:
            return obs, count + 1, 'reached'
        if previous_error is not None and new_error > tolerance and abs(new_error - previous_error) < 0.0001:
            stalled += 1
        else:
            stalled = 0
        if stalled >= 4:
            return obs, count + 1, 'stalled'
        previous_error = new_error
    return obs, max_steps, 'budget'
