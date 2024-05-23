# Reinforcement Learning Assignment

## Student Information
- **Name**: [Your Name]
- **Student ID**: [Your Student ID]
- **Department**: Department of Artificial Intelligence
- **Institution**: Addis Ababa Institute of Technology, School of Information Technology and Engineering

## Assignment Overview

This assignment focuses on implementing various reinforcement learning algorithms to solve the GridWorld problem using the FrozenLake-v1 environment from OpenAI Gymnasium, and the Single-State Multi-Armed Bandit problem.

### GridWorld Problem

The FrozenLake-v1 environment represents the grid world where an agent needs to navigate from a starting point to a goal point while avoiding obstacles. The algorithms implemented for this problem include:

- **Value Iteration**
- **Policy Iteration**
- **Q-Learning**
- **Epsilon-Greedy Policy**
- **Upper Confidence Bound (UCB) Algorithm**

### Single-State Multi-Armed Bandit Problem

This problem involves an agent choosing from multiple actions (arms) to maximize the cumulative reward over a series of time steps. The algorithms implemented for this problem include:

- **Epsilon-Greedy Policy**
- **Upper Confidence Bound (UCB) Algorithm**

## Files

- **gridworld_rl.py**: Contains the implementation of the reinforcement learning algorithms for the GridWorld problem using FrozenLake-v1.
- **multiarmed_bandit.py**: Contains the implementation of the reinforcement learning algorithms for the Single-State Multi-Armed Bandit problem.
- **visualization.py**: Contains the functions to visualize the policies, value functions, and Q-values using matplotlib.
- **README.md**: This file, containing an overview of the assignment, student information, and file descriptions.

## Usage

To run the GridWorld problem with the FrozenLake-v1 environment and visualize the results:

1. Install the required packages:
    ```bash
    pip install gymnasium numpy matplotlib
    ```

2. Run the script for the GridWorld problem:
    ```bash
    python gridworld_rl.py
    ```

3. The script will display the optimal values, policies, and Q-values using matplotlib.

To run the Single-State Multi-Armed Bandit problem and visualize the results:

1. Install the required packages (if not already installed):
    ```bash
    pip install numpy matplotlib
    ```

2. Run the script for the Multi-Armed Bandit problem:
    ```bash
    python multiarmed_bandit.py
    ```

3. The script will display the cumulative rewards and other performance metrics using matplotlib.

## Visualization

The visualization functions provide a graphical representation of the results from the algorithms, including:

- **Value Function Grid**: Shows the optimal value function for each state in the grid.
- **Policy Grid**: Shows the optimal policy for each state in the grid.
- **Q-Values**: Shows the Q-values for each action in the grid.

## Contact

For any questions or further assistance, please contact:

- **Name**: [Your Name]
- **Email**: [Your Email]
- **Department**: Department of Artificial Intelligence, Addis Ababa Institute of Technology
