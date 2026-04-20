"""
PSDT Evaluation

Modified evaluation that maintains cell state across timesteps
within an episode. The cell state accumulates memory as the
episode progresses, giving the model access to information
beyond the context window K.
"""

import numpy as np
import torch


def evaluate_episode_rtg_psdt(
        env,
        state_dim,
        act_dim,
        model,
        max_ep_len=1000,
        scale=1000.,
        state_mean=0.,
        state_std=1.,
        device='cuda',
        target_return=None,
        mode='normal',
):
    """
    Evaluate one episode with PSDT, maintaining cell state across steps.

    The key difference from standard DT evaluation:
    - Cell state is initialized to zeros at episode start
    - Each call to get_action returns an updated cell state
    - Cell state is passed to the next get_action call
    - Memory accumulates over the entire episode
    """

    model.eval()
    model.to(device=device)

    state_mean = torch.from_numpy(state_mean).to(device=device)
    state_std = torch.from_numpy(state_std).to(device=device)

    state = env.reset()
    if mode == 'noise':
        state = state + np.random.normal(0, 0.1, size=state.shape)

    states = torch.from_numpy(state).reshape(1, state_dim).to(device=device, dtype=torch.float32)
    actions = torch.zeros((0, act_dim), device=device, dtype=torch.float32)
    rewards = torch.zeros(0, device=device, dtype=torch.float32)

    ep_return = target_return
    target_return = torch.tensor(ep_return, device=device, dtype=torch.float32).reshape(1, 1)
    timesteps = torch.tensor(0, device=device, dtype=torch.long).reshape(1, 1)

    # ============================================================
    # KEY DIFFERENCE: Initialize cell state for this episode
    # ============================================================
    cell_state = model.init_cell_state(batch_size=1, device=device)

    episode_return, episode_length = 0, 0

    for t in range(max_ep_len):
        actions = torch.cat([actions, torch.zeros((1, act_dim), device=device)], dim=0)
        rewards = torch.cat([rewards, torch.zeros(1, device=device)])

        # ============================================================
        # KEY DIFFERENCE: Pass cell_state and get updated one back
        # ============================================================
        action, cell_state = model.get_action(
            (states.to(dtype=torch.float32) - state_mean) / state_std,
            actions.to(dtype=torch.float32),
            rewards.to(dtype=torch.float32),
            target_return.to(dtype=torch.float32),
            timesteps.to(dtype=torch.long),
            cell_state=cell_state,  # pass current memory
        )

        # Detach cell state to prevent memory buildup
        cell_state = cell_state.detach()

        actions[-1] = action
        action = action.detach().cpu().numpy()

        state, reward, done, _ = env.step(action)

        cur_state = torch.from_numpy(state).to(device=device).reshape(1, state_dim)
        states = torch.cat([states, cur_state], dim=0)
        rewards[-1] = reward

        if mode != 'delayed':
            pred_return = target_return[0, -1] - (reward / scale)
        else:
            pred_return = target_return[0, -1]
        target_return = torch.cat(
            [target_return, pred_return.reshape(1, 1)], dim=1)
        timesteps = torch.cat(
            [timesteps,
             torch.ones((1, 1), device=device, dtype=torch.long) * (t + 1)], dim=1)

        episode_return += reward
        episode_length += 1

        if done:
            break

    return episode_return, episode_length
