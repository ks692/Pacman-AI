# valueIterationAgents.py
# -----------------------
# Licensing Information:  You are free to use or extend these projects for
# educational purposes provided that (1) you do not distribute or publish
# solutions, (2) you retain this notice, and (3) you provide clear
# attribution to UC Berkeley, including a link to http://ai.berkeley.edu.
# 
# Attribution Information: The Pacman AI projects were developed at UC Berkeley.
# The core projects and autograders were primarily created by John DeNero
# (denero@cs.berkeley.edu) and Dan Klein (klein@cs.berkeley.edu).
# Student side autograding was added by Brad Miller, Nick Hay, and
# Pieter Abbeel (pabbeel@cs.berkeley.edu).


# valueIterationAgents.py
# -----------------------
# Licensing Information:  You are free to use or extend these projects for
# educational purposes provided that (1) you do not distribute or publish
# solutions, (2) you retain this notice, and (3) you provide clear
# attribution to UC Berkeley, including a link to http://ai.berkeley.edu.
# 
# Attribution Information: The Pacman AI projects were developed at UC Berkeley.
# The core projects and autograders were primarily created by John DeNero
# (denero@cs.berkeley.edu) and Dan Klein (klein@cs.berkeley.edu).
# Student side autograding was added by Brad Miller, Nick Hay, and
# Pieter Abbeel (pabbeel@cs.berkeley.edu).


import mdp, util

from learningAgents import ValueEstimationAgent
import collections

class ValueIterationAgent(ValueEstimationAgent):
    """
        * Please read learningAgents.py before reading this.*

        A ValueIterationAgent takes a Markov decision process
        (see mdp.py) on initialization and runs value iteration
        for a given number of iterations using the supplied
        discount factor.
    """
    def __init__(self, mdp, discount = 0.9, iterations = 100):
        """
          Your value iteration agent should take an mdp on
          construction, run the indicated number of iterations
          and then act according to the resulting policy.

          Some useful mdp methods you will use:
              mdp.getStates()
              mdp.getPossibleActions(state)
              mdp.getTransitionStatesAndProbs(state, action)
              mdp.getReward(state, action, nextState)
              mdp.isTerminal(state)
        """
        self.mdp = mdp
        self.discount = discount
        self.iterations = iterations
        self.values = util.Counter() # A Counter is a dict with default 0
        self.runValueIteration()

    def runValueIteration(self):
        # Write value iteration code here
        "*** YOUR CODE HERE ***"
        for n in range(self.iterations):
            v_array = self.values.copy()
            for state in self.mdp.getStates():
                action_rewards = util.Counter()
                for action in self.mdp.getPossibleActions(state):
                    action_rewards[action]=self.getQValue(state,action)
                v_array[state] = action_rewards[action_rewards.argMax()]
            self.values=v_array.copy()


    def getValue(self, state):
        """
          Return the value of the state (computed in __init__).
        """
        return self.values[state]


    def computeQValueFromValues(self, state, action):
        """
          Compute the Q-value of action in state from the
          value function stored in self.values.
        """
        "*** YOUR CODE HERE ***"
        q_val = 0
        for p_state in self.mdp.getTransitionStatesAndProbs(state, action):
            reward = self.mdp.getReward(state, action, p_state[0])
            q_val += p_state[1] * (reward + self.discount * self.getValue(p_state[0]))
        return q_val


    def computeActionFromValues(self, state):
        """
          The policy is the best action in the given state
          according to the values currently stored in self.values.

          You may break ties any way you see fit.  Note that if
          there are no legal actions, which is the case at the
          terminal state, you should return None.
        """
        "*** YOUR CODE HERE ***"
        possible_actions = self.mdp.getPossibleActions(state)
        if not possible_actions:
            return None

        action_values = util.Counter()
        for action in possible_actions:
            for trans_state, prob in self.mdp.getTransitionStatesAndProbs(state, action):
                action_values[action] += prob * (self.mdp.getReward(state, action, trans_state)
                                                 + self.discount * self.values[trans_state])

        return action_values.argMax()

    def getPolicy(self, state):
        return self.computeActionFromValues(state)

    def getAction(self, state):
        "Returns the policy at the state (no exploration)."
        return self.computeActionFromValues(state)

    def getQValue(self, state, action):
        return self.computeQValueFromValues(state, action)

class AsynchronousValueIterationAgent(ValueIterationAgent):
    """
        * Please read learningAgents.py before reading this.*

        An AsynchronousValueIterationAgent takes a Markov decision process
        (see mdp.py) on initialization and runs cyclic value iteration
        for a given number of iterations using the supplied
        discount factor.
    """
    def __init__(self, mdp, discount = 0.9, iterations = 1000):
        """
          Your cyclic value iteration agent should take an mdp on
          construction, run the indicated number of iterations,
          and then act according to the resulting policy. Each iteration
          updates the value of only one state, which cycles through
          the states list. If the chosen state is terminal, nothing
          happens in that iteration.

          Some useful mdp methods you will use:
              mdp.getStates()
              mdp.getPossibleActions(state)
              mdp.getTransitionStatesAndProbs(state, action)
              mdp.getReward(state)
              mdp.isTerminal(state)
        """
        ValueIterationAgent.__init__(self, mdp, discount, iterations)

    def runValueIteration(self):
        "*** YOUR CODE HERE ***"
        val_array = util.Counter()
        states = self.mdp.getStates()

        for i in range(self.iterations):
            currentState = states[i % len(states)]
            val_array = self.values.copy()
            possibleVals = []

            if self.mdp.isTerminal(currentState):
                self.values[currentState] = 0
            else:
                for action in self.mdp.getPossibleActions(currentState):
                    tempVal = 0
                    for trans_state, prob in self.mdp.getTransitionStatesAndProbs(currentState, action):
                        tempVal += prob * (self.mdp.getReward(currentState, action, trans_state) + self.discount * val_array[trans_state])
                    possibleVals.append(tempVal)
                self.values[currentState] = max(possibleVals)

class PrioritizedSweepingValueIterationAgent(AsynchronousValueIterationAgent):
    """
        * Please read learningAgents.py before reading this.*

        A PrioritizedSweepingValueIterationAgent takes a Markov decision process
        (see mdp.py) on initialization and runs prioritized sweeping value iteration
        for a given number of iterations using the supplied parameters.
    """
    def __init__(self, mdp, discount = 0.9, iterations = 100, theta = 1e-5):
        """
          Your prioritized sweeping value iteration agent should take an mdp on
          construction, run the indicated number of iterations,
          and then act according to the resulting policy.
        """
        self.theta = theta
        ValueIterationAgent.__init__(self, mdp, discount, iterations)

    def getParents(self):
        parents = {}
        for state in self.mdp.getStates():
            for action in self.mdp.getPossibleActions(state):
                for trans_state, prob in self.mdp.getTransitionStatesAndProbs(state, action):
                    if not (prob == 0):
                        if trans_state not in parents:
                            parents[trans_state] = [state]
                        else:
                            parents[trans_state].append(state)
        return parents

    def runValueIteration(self):
        "*** YOUR CODE HERE ***"
        parents = self.getParents()
        deque = util.PriorityQueue()
        for state in self.mdp.getStates():
            if self.mdp.isTerminal(state):
                continue
            diff = abs(self.values[state] - self.getQValue(state, self.computeActionFromValues(state)))
            deque.push(state, -diff)
        for i in range(self.iterations):
            if deque.isEmpty():
                return
            state = deque.pop()
            if not self.mdp.isTerminal(state):
                actions = self.mdp.getPossibleActions(state)
                max_val=float('-inf')
                for action in actions:
                    tempValue = 0
                    for trans_state, prob in self.mdp.getTransitionStatesAndProbs(state, action):
                        tempValue += prob * (self.mdp.getReward(state, action, trans_state)
                                          + self.discount * self.values[trans_state])
                    max_val = max(max_val, tempValue)
                self.values[state] = max_val
            for parent in parents[state]:
                diff = abs(self.values[parent] - self.getQValue(parent, self.computeActionFromValues(parent)))
                if diff > self.theta:
                    deque.update(parent, -diff)



