#!/usr/bin/env python3
# -*- coding: utf-8 -*-
"""
Created on Fri Aug 23 16:11:22 2019

@author: huiminren
# Modified By Yanhua Li on 08/19/2023 for gymnasium==0.29.0
"""
import numpy as np
import random
from collections import defaultdict
import gymnasium as gym 
#-------------------------------------------------------------------------
'''
    Monte-Carlo
    In this problem, you will implememnt an AI player for Blackjack.
    The main goal of this problem is to get familar with Monte-Carlo algorithm.

    You could test the correctness of your code
    by typing 'nosetests -v mc_test.py' in the terminal.
'''
#-------------------------------------------------------------------------

gym.make('Blackjack-v1', natural=False, sab=False)

def initial_policy(observation):
    """A policy that sticks if the player score is >= 20 and hit otherwise

    Parameters:
    -----------
    observation:
    Returns:
    --------
    action: 0 or 1
        0: STICK
        1: HIT
    """
    player_current_sum = observation[0]
    if player_current_sum >= 20:
        action = 0
    else:
        action = 1    
    
    return action


def mc_prediction(policy, env, n_episodes, gamma=1.0):
    """Given policy using sampling to calculate the value function
        by using Monte Carlo first visit algorithm.

    Parameters:
    -----------
    policy: function
        A function that maps an obversation to action probabilities
    env: function
        OpenAI gym environment
    n_episodes: int
        Number of episodes to sample
    gamma: float
        Gamma discount factor
    Returns:
    --------
    V: defaultdict(float)
        A dictionary that maps from state to value
    """
    # initialize empty dictionaries
    returns_sum = defaultdict(float)
    returns_count = defaultdict(float)
    # a nested dictionary that maps state -> value
    V = defaultdict(float)

    for episode_num in range(n_episodes):
        episode=[]
        state, _= env.reset()
        while True:
            action=policy(state)
            next_state,reward,terminated,_,_=env.step(action)
            done=terminated
            
            episode.append((state, action, reward))
            state=next_state
            
            if done:
                break
            
        G = 0
        visited_states=set()
        for t in range(len(episode)-1, -1, -1):
            state, action, reward = episode[t]

            G = gamma * G + reward

            if state not in visited_states:
                
                returns_sum[state] += G
                returns_count[state] += 1

                V[state] = returns_sum[state] / returns_count[state]

                visited_states.add(state)
                
    return V


def epsilon_greedy(Q, state, nA, epsilon=0.1):
    """Selects epsilon-greedy action for supplied state.

    Parameters:
    -----------
    Q: dict()
        A dictionary  that maps from state -> action-values,
        where Q[s][a] is the estimated action value corresponding to state s and action a.
    state: 
        current state
    nA: int
        Number of actions in the environment
    epsilon: float
        The probability to select a random action, range between 0 and 1

    Returns:
    --------
    action: int
        action based current state
    Hints:
    ------
    With probability (1 - epsilon) choose the greedy action.
    With probability epsilon choose an action at random.
    """
    
    
    q_values = Q[state] if state in Q else np.zeros(nA)

    if random.random() < (1.0 - epsilon):
        action = int(np.argmax(q_values))
    else:
        action = int(random.randrange(nA))
    
    return action


def mc_control_epsilon_greedy(env, n_episodes, gamma=1.0, epsilon=0.1):
    """Monte Carlo control with exploring starts.
        Find an optimal epsilon-greedy policy.

    Parameters:
    -----------
    env: function
        OpenAI gym environment
    n_episodes: int
        Number of episodes to sample
    gamma: float
        Gamma discount factor
    epsilon: float
        The probability to select a random action, range between 0 and 1
    Returns:
    --------
    Q: dict()
        A dictionary  that maps from state -> action-values,
        where Q[s][a] is the estimated action value corresponding to state s and action a.
    Hint:
    -----
    You could consider decaying epsilon, i.e. epsilon = epsilon-0.1/n_episode during each episode
    and episode must > 0.
    """

    returns_sum = defaultdict(float)
    returns_count = defaultdict(float)
    # a nested dictionary that maps state -> (action -> action-value)
    # e.g. Q[state] = np.darrary(nA)
    Q = defaultdict(lambda: np.zeros(env.action_space.n))

    for episode_num in range(n_episodes):
        nA = env.action_space.n           
        episode=[]
        state, _= env.reset()
        while True:
            action=epsilon_greedy(Q,state, nA, epsilon)
            next_state,reward,terminated,_,_=env.step(action)
            done=terminated
            
            episode.append((state, action, reward))
            state=next_state
            
            if done:
                break
            
        G = 0
        visited_states=set()
        for t in range(len(episode)-1, -1, -1):
            state, action, reward = episode[t]

            G = gamma * G + reward
            if state not in visited_states:
                returns_sum[(state, action)]+=G
                returns_count[(state,action)]+=1
                Q[state][action]=returns_sum[(state, action)]/returns_count[(state, action)]
                visited_states.add((state,action))

    return Q
