import torch
import gymnasium as gym
import numpy as np
import argparse
import matplotlib.pyplot as plt
from agent import Agent, Policy
from cp_cont import CartPoleEnv
import pandas as pd

import sys

import os
os.environ["KMP_DUPLICATE_LIB_OK"]="TRUE"


# Policy training function
def train(env_name, print_things=True, train_run_id=0, train_episodes=1000, reward_mode = None):
    # Create a Gym environment
    env = gym.make(env_name)

    # Get dimensionalities of actions and observations
    action_space_dim = env.action_space.shape[-1] # it's only 1 now, but it's real valued
    observation_space_dim = env.observation_space.shape[-1]

    print('action_space_dim:', action_space_dim)
    print('observation_space_dim:', observation_space_dim)

    # Instantiate agent and its policy
    policy = Policy(observation_space_dim, action_space_dim)
    agent = Agent(policy, reward_mode = reward_mode)

    # Arrays to keep track of rewards
    reward_history, timestep_history = [], []
    average_reward_history = []

    # Run actual training
    for episode_number in range(train_episodes):
        reward_sum, timesteps = 0, 0
        done = False
        # Reset the environment and observe the initial state
        observation, _ = env.reset()

        # Loop until the episode is over
        while not done:
            # Get action from the agent
            action, action_probabilities = agent.get_action(observation, episode_number=episode_number)
            previous_observation = observation

            # Perform the action on the environment, get new state and reward
            observation, reward, truncated, terminated, info = env.step(action.detach().numpy())
            done = terminated or truncated
            # Store action's outcome (so that the agent can improve its policy)
            agent.store_outcome(previous_observation, action_probabilities, action, reward)

            # Store total episode reward
            reward_sum += reward
            timesteps += 1

        if print_things:
            print("Episode {} finished. Total reward: {:.3g} ({} timesteps)"
                  .format(episode_number, reward_sum, timesteps))

            print('Current sigma squared:', agent.policy.sigmasquared)

        # Bookkeeping (mainly for generating plots)
        reward_history.append(reward_sum)
        timestep_history.append(timesteps)
        if episode_number > 100:
            avg = np.mean(reward_history[-100:])
        else:
            avg = np.mean(reward_history)
        average_reward_history.append(avg)

        # Let the agent do its magic (update the policy)
        agent.episode_finished(episode_number)
    print(f"Average reward for episode: {sum(average_reward_history)/len(average_reward_history)}")

    # Training is finished - plot rewards
    if print_things:
        plt.plot(reward_history)
        plt.plot(average_reward_history)
        plt.legend(["Reward", "100-episode average"])

        plt.xlabel('episode', labelpad=12, fontweight='bold')
        plt.ylabel('cumulative reward', labelpad=12, fontweight='bold')
        plt.title("Reward history")
        plt.savefig("./figures/model_%s_%d_%s.png" % (env_name, train_run_id, reward_mode))
        plt.show()
        plt.close()
        print("Training finished.")

    data = pd.DataFrame({"episode": np.arange(len(reward_history)),
                         "train_run_id": [train_run_id]*len(reward_history),
                         # TODO: Change algorithm name for plots, if you want
                         "algorithm": ["PG"]*len(reward_history),
                         "reward": reward_history})
    torch.save( agent.policy.state_dict(), "./checkpoints/model_%s_%d_%s.mdl" % (env_name, train_run_id, reward_mode))
    return data


# Function to test a trained policy
def test(env_name, episodes, params, render=True):
    # Create a Gym environment
    env = gym.make(env_name)

    # Get dimensionalities of actions and observations
    action_space_dim = env.action_space.shape[-1]
    observation_space_dim = env.observation_space.shape[-1]

    # Instantiate agent and its policy
    policy = Policy(observation_space_dim, action_space_dim)
    policy.load_state_dict(params)
    agent = Agent(policy)

    test_reward, test_len = 0, 0
    for ep in range(episodes):
        done = False
        observation, _ = env.reset()
        while not done:
            # Similar to the training loop above -
            # get the action, act on the environment, save total reward
            # (evaluation=True makes the agent always return what it thinks to be
            # the best action - there is no exploration at this point)
            action, _ = agent.get_action(observation, evaluation=True)

            observation, reward, terminated, truncated, info = env.step(
                action.detach().cpu().numpy())
            done = terminated or truncated

            if render:
                env.render()
            test_reward += reward
            test_len += 1
    print("Average test reward:", test_reward/episodes, "episode length:", test_len/episodes)


if __name__ == "__main__":
    parser = argparse.ArgumentParser()
    parser.add_argument("--test", "-t", type=str, default=None, help="Model to be tested")
    parser.add_argument("--env", type=str, default="ContinuousCartPole-v0", help="Environment to use")
    parser.add_argument("--train_episodes", type=int, default=1000, help="Number of episodes to train for")
    parser.add_argument("--render_test", action='store_true', help="Render test")
    parser.add_argument("--rew", choices=["r", "b", "n"], required=True,
                        help="Reward mode: r = run reinforce without baseline, b = run reinforce with baseline, n = run reinforce without discounted rewards normalized to zero mean and unit variance")

    args = parser.parse_args()

    # If no model was passed, train a policy from scratch.
    # Otherwise load the policy from the file and go directly to testing.

    os.makedirs("./figures", exist_ok=True)
    os.makedirs("./checkpoints", exist_ok=True)

    if args.test is None:
        try:
            train(args.env, train_episodes=args.train_episodes, reward_mode = args.rew)
        # Handle Ctrl+C - save model and go to tests
        except KeyboardInterrupt:
            print("Interrupted!")
    else:
        state_dict = torch.load(args.test)
        print("Testing...")
        test(args.env, 100, state_dict, args.render_test)

