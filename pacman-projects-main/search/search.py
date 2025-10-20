# search.py
# ---------
# Licensing Information:  You are free to use or extend these projects for
# educational purposes provided that (1) you do not distribute or publish
# solutions, (2) you retain this notice, and (3) you provide clear
# attribution to UC Berkeley, including a link to http://ai.berkeley.edu.
# 
# # Attribution Information: The Pacman AI projects were developed at UC Berkeley.
# The core projects and autograders were primarily created by John DeNero
# (denero@cs.berkeley.edu) and Dan Klein (klein@cs.berkeley.edu).
# Student side autograding was added by Brad Miller, Nick Hay, and
# Pieter Abbeel (pabbeel@cs.berkeley.edu).


"""
In search.py, you will implement generic search algorithms which are called by
Pacman agents (in search_agents.py).
"""
import util

class SearchProblem:
    """
    This class outlines the structure of a search problem, but doesn't implement
    any of the methods (in obj-oriented terminology: an abstract class).

    You do not need to change anything in this class, ever.
    """

    def get_start_state(self):
        """
        Returns the start state for the search problem.
        """
        util.raise_not_defined()

    def is_goal_state(self, state):
        """
          state: Search state

        Returns True if and only if the state is a valid goal state.
        """
        util.raise_not_defined()

    def get_successors(self, state):
        """
          state: Search state

        For a given state, this should return a list of triples, (successor,
        action, stepCost), where 'successor' is a successor to the current
        state, 'action' is the action required to get there, and 'stepCost' is
        the incremental cost of expanding to that successor.
        """
        util.raise_not_defined()

    def get_cost_of_actions(self, actions):
        """
         actions: A list of actions to take

        This method returns the total cost of a particular sequence of actions.
        The sequence must be composed of legal moves.
        """
        util.raise_not_defined()


def tiny_maze_search(problem):
    """
    Returns a sequence of moves that solves tinyMaze.  For any other maze, the
    sequence of moves will be incorrect, so only use this for tinyMaze.
    """
    from game import Directions
    s = Directions.SOUTH
    w = Directions.WEST
    return  [s, s, w, s, w, w, s, w]

# def addSuccessors(problem, addCost=True):

class SearchNode:
    def __init__(self, parent, node_info):
        """
            parent: parent SearchNode.

            node_info: tuple with three elements => (coord, action, cost)

            coord: (x,y) coordinates of the node position

            action: Direction of movement required to reach node from
            parent node. Possible values are defined by class Directions from
            game.py

            cost: cost of reaching this node from the starting node.
        """

        self.__state = node_info[0]
        self.action = node_info[1]
        self.cost = node_info[2] if parent is None else node_info[2] + parent.cost
        self.parent = parent

    # The coordinates of a node cannot be modified, se we just define a getter.
    # This allows the class to be hashable.
    @property
    def state(self):
        return self.__state

    def get_path(self):
        path = []
        current_node = self
        while current_node.parent is not None:
            path.append(current_node.action)
            current_node = current_node.parent
        path.reverse()
        return path
    
    # Consider 2 nodes to be equal if their coordinates are equal (regardless of everything else)
    # def __eq__(self, __o: obj) -> bool:
    #     if (type(__o) is SearchNode):
    #         return self.__state == __o.__state
    #     return False

    # # def __hash__(self) -> int:
    # #     return hash(self.__state)

def depth_first_search(problem):
    """
    Search the deepest nodes in the search tree first.

    Your search algorithm needs to return a list of actions that reaches the
    goal. Make sure to implement a graph search algorithm.

    To get started, you might want to try some of these simple commands to
    understand the search problem that is being passed in:

    print("Start:", problem.get_start_state())
    print("Is the start a goal?", problem.is_goal_state(problem.get_start_state()))
    print("Start's successors:", problem.get_successors(problem.get_start_state()))
    """
    # Frontier holds (state, path) pairs, using a LIFO stack implements DFS
    frontier = util.Stack()
    start_state = problem.get_start_state()
    frontier.push((start_state, []))

    # Track visited states to avoid re-expansion (graph search)
    visited = set()

    while not frontier.is_empty():
        state, path = frontier.pop()

        # Goal test on pop ensures we return a valid action sequence as soon as found
        if problem.is_goal_state(state):
            return path

        if state in visited:
            continue
        visited.add(state)

        # Expand current state and push successors with their extended paths
        for successor, action, _ in problem.get_successors(state):
            if successor not in visited:
                frontier.push((successor, path + [action]))

    # No solution found, return empty plan
    return []



def breadth_first_search(problem):
    """Search the shallowest nodes in the search tree first."""
    # Frontier holds (state, path) pairs. Queue, FIFO for BFS
    frontier = util.Queue()
    start_state = problem.get_start_state()
    frontier.push((start_state, []))

    # Track visited states to ensure each state is expanded at most once
    visited = set()

    while not frontier.is_empty():
        state, path = frontier.pop()

        if problem.is_goal_state(state):
            return path

        if state in visited:
            continue
        visited.add(state)

        for successor, action, _ in problem.get_successors(state):
            if successor not in visited:
                frontier.push((successor, path + [action]))

    # No solution found, return empty plan by convention
    return []

def uniform_cost_search(problem):
    """Search the node of least total cost first."""
    # Frontier holds (state, path, path_cost). Priority is path_cost
    frontier = util.PriorityQueue()
    start_state = problem.get_start_state()
    frontier.push((start_state, [], 0), 0)

    # Best known cost to reach each visited state to avoid re-processing worse paths
    best_cost = {}

    while not frontier.is_empty():
        state, path, cost_so_far = frontier.pop()

        # If we have already a better path to this state, skip
        if state in best_cost and cost_so_far > best_cost[state]:
            continue

        if problem.is_goal_state(state):
            return path

        best_cost[state] = cost_so_far

        for successor, action, step_cost in problem.get_successors(state):
            new_cost = cost_so_far + step_cost
            # Only consider pushing if we haven't seen successor or found a cheaper path
            if successor not in best_cost or new_cost < best_cost[successor]:
                frontier.push((successor, path + [action], new_cost), new_cost)

    # No solution found, return empty plan by convention
    return []

def null_heuristic(state, problem=None):
    """
    A heuristic function estimates the cost from the current state to the nearest
    goal in the provided SearchProblem.  This heuristic is trivial.
    """
    return 0

def a_star_search(problem, heuristic=null_heuristic):
    """Search the node that has the lowest combined cost and heuristic first."""
    # A* frontier holds (state, path_so_far, g_cost) and is prioritized by f = g + h
    # We perform goal testing when a node is popped from the frontier, which, together with a consistent heuristic, guarantees optimality
    frontier = util.PriorityQueue()

    start_state = problem.get_start_state()
    start_g_cost = 0
    start_f_cost = start_g_cost + heuristic(start_state, problem)
    frontier.push((start_state, [], start_g_cost), start_f_cost)

    # Record best known g-cost to each state to prune dominated entries
    best_g_cost = {}

    while not frontier.is_empty():
        state, path, g_cost = frontier.pop()

        # Discard outdated entries that are worse than a known path to this state
        if state in best_g_cost and g_cost > best_g_cost[state]:
            continue

        # Optimal goal detection (with consistent heuristic) when removing from frontier
        if problem.is_goal_state(state):
            return path

        best_g_cost[state] = g_cost

        # Expand successors: compute new g and priority f = g + h
        for successor, action, step_cost in problem.get_successors(state):
            new_g = g_cost + step_cost
            # Only consider successor if we have not seen it or found a cheaper path to it
            if successor not in best_g_cost or new_g < best_g_cost[successor]:
                f_priority = new_g + heuristic(successor, problem)
                frontier.push((successor, path + [action], new_g), f_priority)

    # If no solution is found, return an empty plan by convention
    return []

# Abbreviations
bfs = breadth_first_search
dfs = depth_first_search
astar = a_star_search
ucs = uniform_cost_search
