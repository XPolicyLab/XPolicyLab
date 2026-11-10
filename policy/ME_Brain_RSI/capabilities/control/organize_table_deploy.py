"""Official environment bridge. The policy receives observations via the server."""
import os


def eval_one_episode(TASK_ENV, model_client):
    model_client.call(func_name="reset")
    limit = int(os.environ.get("COAP_PROBE_STEPS", "160"))
    probe = os.environ.get("COAP_PROBE_ONLY") == "1"
    step = 0
    while not TASK_ENV.is_episode_end():
        obs = TASK_ENV.get_obs()
        model_client.call(func_name="update_obs", obs=obs)
        if probe and step >= limit:
            break
        actions = model_client.call(func_name="get_action")
        for action in actions:
            TASK_ENV.take_action(action)
            step += 1
            if TASK_ENV.is_episode_end():
                break
    # Final observation makes grasping/placement failures reviewable.
    model_client.call(func_name="update_obs", obs=TASK_ENV.get_obs())
    model_client.call(func_name="finish_episode")


def eval_one_episode_batch(TASK_ENV, model_client):
    return eval_one_episode(TASK_ENV, model_client)
