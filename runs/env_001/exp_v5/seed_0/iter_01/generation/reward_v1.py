def compute_reward(obs, action, next_obs, original_reward, info, training_progress=0.0):
    # Extract observations
    # Position relative to target (goal is at origin)
    x_pos = obs[0]
    y_pos = obs[1]
    next_x_pos = next_obs[0]
    next_y_pos = next_obs[1]
    
    # Velocity
    x_vel = next_obs[2]
    y_vel = next_obs[3]
    
    # Orientation
    body_angle = next_obs[4]
    angular_vel = next_obs[5]
    
    # Contact flags
    left_contact = next_obs[6]
    right_contact = next_obs[7]
    
    # ========== Component 1: Progress Delta Reward (Main Learning Signal) ==========
    # Distance to target (Euclidean distance)
    current_dist = (x_pos ** 2 + y_pos ** 2) ** 0.5
    next_dist = (next_x_pos ** 2 + next_y_pos ** 2) ** 0.5
    
    # Progress: positive when moving closer to target
    progress_delta = current_dist - next_dist
    
    # Scale progress reward - encourage consistent progress
    progress_reward = 5.0 * progress_delta
    
    # ========== Component 2: Stability Penalty (Light Constraint) ==========
    # Penalize high speed, large angle, and high angular velocity
    speed = (x_vel ** 2 + y_vel ** 2) ** 0.5
    angle_penalty = abs(body_angle)
    angular_vel_penalty = abs(angular_vel)
    
    # Small weights to avoid over-constraining
    stability_penalty = -0.1 * speed - 0.5 * angle_penalty - 0.05 * angular_vel_penalty
    
    # ========== Component 3: Soft Landing Proxy (Task Completion Hint) ==========
    # Small bonus when near target, slow, stable, and both supports contact
    near_target = next_dist < 0.3
    low_speed = speed < 0.5
    stable_angle = abs(body_angle) < 0.2
    both_contact = (left_contact > 0.5) and (right_contact > 0.5)
    
    soft_landing_bonus = 0.0
    if near_target and low_speed and stable_angle and both_contact:
        soft_landing_bonus = 2.0
    
    # ========== Total Reward ==========
    total_reward = progress_reward + stability_penalty + soft_landing_bonus
    
    # ========== Components Dict ==========
    components = {
        "progress_reward": progress_reward,
        "stability_penalty": stability_penalty,
        "soft_landing_bonus": soft_landing_bonus,
        "total_reward": total_reward
    }
    
    return float(total_reward), components