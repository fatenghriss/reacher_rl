from unityagents import UnityEnvironment
import numpy as np
import random
from agents.random_agent import RandomAgent
import torch
from training.train import train
import matplotlib.pyplot as plt

def main():

    env = UnityEnvironment(file_name="/home/faten/projects/deep-reinforcement-learning/p2_continuous-control/Reacher_Linux/Reacher.x86_64")

    brain_name = env.brain_names[0]
    brain = env.brains[brain_name]

    action_size = brain.vector_action_space_size
    env_info = env.reset(train_mode=True)[brain_name]
    state = env_info.vector_observations[0]
    state_size = len(state)

    # number of agents
    num_agents = len(env_info.agents)
    print('Number of agents:', num_agents)

    # size of each action
    action_size = brain.vector_action_space_size
    print('Size of each action:', action_size)

    # agent = RandomAgent(num_agents,state_size,action_size,seed=0)


    scores = np.zeros(num_agents)                          # initialize the score (for each agent)
    while True:
        actions = np.random.randn(num_agents, action_size) # select an action (for each agent)
        actions = np.clip(actions, -1, 1)                  # all actions between -1 and 1
        env_info = env.step(actions)[brain_name]           # send all actions to tne environment
        next_states = env_info.vector_observations         # get next state (for each agent)
        rewards = env_info.rewards                         # get reward (for each agent)
        dones = env_info.local_done                        # see if episode finished
        scores += env_info.rewards                         # update the score (for each agent)
        states = next_states                               # roll over states to next time step
        if np.any(dones):                                  # exit loop if episode finished
            break

    print('Total score (averaged over agents) this episode: {}'.format(np.mean(scores)))

main()