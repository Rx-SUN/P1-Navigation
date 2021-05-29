[//]: # (Image References)
[image1]: https://user-images.githubusercontent.com/10624937/42135619-d90f2f28-7d12-11e8-8823-82b970a54d7e.gif "Trained Agent"

# Project 1: Navigation
![Trained Agent][image1]


### Introduction

This is the first project of Udacity's DRL Nanodegree program. The task is to navigate the agent to pick up yellow bananas. The agent should be trained using reinforcement learning algorithm. I choose DQN(Deep Q-Network) to solve this problem.  
### Reward
Picking up a yellow banana gives a reward of +1 while a blue banana with a reward of -1. That intuitively means the agent should collect as many yellow bananas as possible and at the same time pick as less blue bananas as possible. 
### Environment
The state space A reward of +1 is provided for collecting a yellow banana, and a reward of -1 is provided for collecting a blue banana.  Thus, the goal of your agent is to collect as many yellow bananas as possible while avoiding blue bananas.  

There are 37 dimensions in the state space. They represent the information which the agent can percept, such as the velocity. Using the information and contains the agent's velocity, along with ray-based perception of objects around agent's forward direction. The agent learns to choose actions based on the information and tries to make the reward as high as possible. There are 4 actions here: 
- **`0`** - move forward.
- **`1`** - move backward.
- **`2`** - turn left.
- **`3`** - turn right.

The task is episodic, and in order to solve the environment, the agent must get an average score of +13 over 100 consecutive episodes.

### Getting Started
1. Check the dependencies [here](https://github.com/udacity/deep-reinforcement-learning/#dependencies), and follow the instructions.
2. Download the environment from one of the links below.  You need only select the environment that matches your operating system:
    - Linux: [click here](https://s3-us-west-1.amazonaws.com/udacity-drlnd/P1/Banana/Banana_Linux.zip)
    - Mac OSX: [click here](https://s3-us-west-1.amazonaws.com/udacity-drlnd/P1/Banana/Banana.app.zip)
    - Windows (32-bit): [click here](https://s3-us-west-1.amazonaws.com/udacity-drlnd/P1/Banana/Banana_Windows_x86.zip)
    - Windows (64-bit): [click here](https://s3-us-west-1.amazonaws.com/udacity-drlnd/P1/Banana/Banana_Windows_x86_64.zip)
    
    (_For Windows users_) Check out [this link](https://support.microsoft.com/en-us/help/827218/how-to-determine-whether-a-computer-is-running-a-32-bit-version-or-64) if you need help with determining if your computer is running a 32-bit version or 64-bit version of the Windows operating system.

    (_For AWS_) If you'd like to train the agent on AWS (and have not [enabled a virtual screen](https://github.com/Unity-Technologies/ml-agents/blob/master/docs/Training-on-Amazon-Web-Service.md)), then please use [this link](https://s3-us-west-1.amazonaws.com/udacity-drlnd/P1/Banana/Banana_Linux_NoVis.zip) to obtain the environment.

3. Place the file in the DRLND GitHub repository, in the `p1_navigation/` folder, and unzip (or decompress) the file. 

### Instructions

Open Navigation.ipynb with jupyter notebook and run the blocks in order. It contains both training and testing part.


