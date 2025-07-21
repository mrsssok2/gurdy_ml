#!/usr/bin/env python
import rospy
import numpy as np
import time
import gym
from gym import spaces
from gym.utils import seeding
from geometry_msgs.msg import Point, Vector3
import gym.envs.registration
from std_msgs.msg import Float64
from pyquaternion import Quaternion
import math
import tf

# Import necessary ROS message types
from sensor_msgs.msg import JointState
from nav_msgs.msg import Odometry
from gazebo_msgs.msg import ContactsState, ModelStates

# Define a function to convert quaternion to Euler angles
def euler_from_quaternion(quaternion):
    """
    Convert quaternion to Euler angles (roll, pitch, yaw) using pyquaternion
    
    Args:
        quaternion: A quaternion as [x, y, z, w]
        
    Returns:
        tuple: (roll, pitch, yaw) in radians
    """
    q = Quaternion(w=quaternion[3], x=quaternion[0], y=quaternion[1], z=quaternion[2])
    euler = q.yaw_pitch_roll
    return (euler[2], euler[1], euler[0])  # roll, pitch, yaw

class MyGurdySingleLegEnv(gym.Env):
    """Superclass for Gurdy robot environments"""
    
    metadata = {'render.modes': ['human']}
    
    def __init__(self):
        """
        Initialize the Gurdy single leg environment
        """
        super(MyGurdySingleLegEnv, self).__init__()
        
        # Initialize variables
        self._joint_states = JointState()
        self._odom = Odometry()
        self._model_states = None
        self._bumper_states = None
        self._has_fallen = False
        self._check_all_systems_ready()
        
        # Define joint names for all 6 upper leg joints
        self.joint_names = [
            "head_upperlegM1_joint", 
            "head_upperlegM2_joint", 
            "head_upperlegM3_joint",
            "head_upperlegM4_joint",
            "head_upperlegM5_joint",
            "head_upperlegM6_joint"
        ]
        
        # Define joint controllers
        self.publishers_array = []
        self._joint_pubisher1 = rospy.Publisher(
            '/gurdy/head_upperlegM1_joint_position_controller/command',
            Float64,
            queue_size=1
        )
        self._joint_pubisher2 = rospy.Publisher(
            '/gurdy/head_upperlegM2_joint_position_controller/command',
            Float64,
            queue_size=1
        )
        self._joint_pubisher3 = rospy.Publisher(
            '/gurdy/head_upperlegM3_joint_position_controller/command',
            Float64,
            queue_size=1
        )
        self._joint_pubisher4 = rospy.Publisher(
            '/gurdy/head_upperlegM4_joint_position_controller/command',
            Float64,
            queue_size=1
        )
        self._joint_pubisher5 = rospy.Publisher(
            '/gurdy/head_upperlegM5_joint_position_controller/command',
            Float64,
            queue_size=1
        )
        self._joint_pubisher6 = rospy.Publisher(
            '/gurdy/head_upperlegM6_joint_position_controller/command',
            Float64,
            queue_size=1
        )
        
        self.publishers_array.append(self._joint_pubisher1)
        self.publishers_array.append(self._joint_pubisher2)
        self.publishers_array.append(self._joint_pubisher3)
        self.publishers_array.append(self._joint_pubisher4)
        self.publishers_array.append(self._joint_pubisher5)
        self.publishers_array.append(self._joint_pubisher6)
        
        # Create subscribers
        rospy.Subscriber("/gurdy/joint_states", JointState, self._joints_callback)
        rospy.Subscriber("/gurdy/odom", Odometry, self._odom_callback)
        rospy.Subscriber("/gazebo/model_states", ModelStates, self._model_states_callback)
        
        # Add a bumper contact sensor to detect falls
        rospy.Subscriber("/gurdy/head_bumper", ContactsState, self._bumper_callback)
        
        # Wait for publishers to connect
        self._check_publishers_connection()
        
        # Define action and observation spaces
        self.action_space = spaces.Discrete(5)
        
        # Add height of the robot head to observations
        self.observation_space = spaces.Box(
            low=np.array([-1.0, -1.0, -1.0, -1.0, -1.0, -1.0, 0.0, 0.0, 0.0]),  # min values for 6 joints, speed, distance, height
            high=np.array([1.0, 1.0, 1.0, 1.0, 1.0, 1.0, 2.0, 10.0, 1.0]),      # max values for 6 joints, speed, distance, height
            dtype=np.float32
        )
        
        # Initialize the seed
        self.seed()
        
        # Initialize ROS-related variables
        self.joint_positions = [0.0, 0.0, 0.0, 0.0, 0.0, 0.0]
        self.base_position = Point()
        self.head_height = 0.0  # Height of the robot's head
        self.start_point = None
        self.cumulated_steps = 0
        self.cumulated_reward = 0
        
        rospy.loginfo("Starting RobotGazeboEnv")
    
    def _joints_callback(self, data):
        """
        Callback for joint states
        
        Args:
            data (JointState): Joint state message
        """
        self._joint_states = data
    
    def _odom_callback(self, data):
        """
        Callback for odometry
        
        Args:
            data (Odometry): Odometry message
        """
        self._odom = data
    
    def _model_states_callback(self, data):
        """
        Callback for model states
        
        Args:
            data (ModelStates): Model states message
        """
        self._model_states = data
        
        # Find the Gurdy model in the model states
        try:
            gurdy_index = data.name.index("gurdy")
            self.head_height = data.pose[gurdy_index].position.z
        except (ValueError, IndexError):
            pass  # Gurdy not found in model states
    
    def _bumper_callback(self, data):
        """
        Callback for bumper contact sensor
        
        Args:
            data (ContactsState): Contact states message
        """
        self._bumper_states = data
        
        # Check if there are any contacts (indicating a fall)
        if data.states:
            self._has_fallen = True
        
    def check_robot_fallen(self):
        """
        Check if the robot has fallen (head is too close to the ground)
        
        Returns:
            bool: True if fallen, False otherwise
        """
        # Check using bumper contact if available
        if self._has_fallen:
            return True
        
        # Check using height (if bumper didn't detect a fall)
        # If head height is less than a threshold (e.g., 0.1m), consider the robot has fallen
        if self.head_height < 0.1:
            return True
            
        return False
    
    def _check_all_systems_ready(self):
        """
        Check if all sensors are ready
        """
        # Check joint states
        try:
            self._joint_states = rospy.wait_for_message("/gurdy/joint_states", JointState, timeout=5.0)
            rospy.loginfo("Joint states ready")
        except rospy.ROSException:
            rospy.logerr("Joint states not available")
            return False
        
        # Check odometry
        try:
            self._odom = rospy.wait_for_message("/gurdy/odom", Odometry, timeout=5.0)
            rospy.loginfo("Odometry ready")
        except rospy.ROSException:
            rospy.logerr("Odometry not available")
            return False
        
        # Check model states
        try:
            self._model_states = rospy.wait_for_message("/gazebo/model_states", ModelStates, timeout=5.0)
            rospy.loginfo("Model states ready")
        except rospy.ROSException:
            rospy.logerr("Model states not available")
            # Not critical, continue anyway
        
        rospy.loginfo("All sensors are ready")
        return True
    
    def _check_publishers_connection(self):
        """
        Check that all publishers are connected
        """
        rate = rospy.Rate(10)  # 10Hz
        for publisher_object in self.publishers_array:
            connected = False
            while not connected:
                connected = publisher_object.get_num_connections() > 0
                if not connected:
                    rate.sleep()
                    rospy.loginfo("Waiting for subscribers to joint position controllers...")
        
        rospy.loginfo("Joint position publishers connected")
    
    def seed(self, seed=None):
        """
        Set the random seed
        """
        self.np_random, seed = seeding.np_random(seed)
        return [seed]
    
    def reset(self):
        """
        Reset the environment
        
        Returns:
            list: Initial observation
        """
        # Reset ROS-related variables
        self.joint_positions = [0.0, 0.0, 0.0, 0.0, 0.0, 0.0]
        self.base_position = self._odom.pose.pose.position
        self.start_point = self.base_position
        self.cumulated_steps = 0
        self.cumulated_reward = 0
        self._has_fallen = False  # Reset fallen state
        
        # Move joints to initial position
        self._set_init_pose()
        
        # Initialize environment variables
        self._init_env_variables()
        
        # Get observation
        observation = self._get_obs()
        
        return observation
    
    def step(self, action):
        """
        Execute action and return new state
        
        Args:
            action (int): Action to take
            
        Returns:
            list: New observation
            float: Reward
            bool: Done flag
            dict: Info dictionary
        """
        # Increment step counter
        self.cumulated_steps += 1
        
        # Execute action
        self._set_action(action)
        
        # Get observation
        observation = self._get_obs()
        
        # Check if robot has fallen
        fallen = self.check_robot_fallen()
        
        # Check if done
        done = self._is_done(observation, fallen)
        
        # Calculate reward
        reward = self._compute_reward(observation, done, fallen)
        self.cumulated_reward += reward
        
        # Return observation, reward, done, info
        info = {
            'steps': self.cumulated_steps,
            'cumulated_reward': self.cumulated_reward,
            'fallen': fallen
        }
        
        return observation, reward, done, info
    
    def _set_init_pose(self):
        """
        Set the robot in its init pose
        """
        # Initial position - centered joints
        initial_joints = [0.0, 0.0, 0.0, 0.0, 0.0, 0.0]
        self.move_joints(initial_joints)
        
        # Wait for the joints to settle
        time.sleep(0.1)
    
    def _init_env_variables(self):
        """
        Initialize environment variables
        """
        # Store the initial position
        self.start_point = self._odom.pose.pose.position
    
    def move_joints(self, joint_positions):
        """
        Move robot joints with improved performance
        
        Args:
            joint_positions (list): List of joint positions to set
        """
        i = 0
        for publisher_object in self.publishers_array:
            joint_value = Float64()
            joint_value.data = joint_positions[i]
            publisher_object.publish(joint_value)
            i += 1
    
    def _get_obs(self):
        """
        Get observation
        
        Returns:
            np.array: [joint_angles, linear_speed, distance]
        """
        raise NotImplementedError()
    
    def _set_action(self, action):
        """
        Set action
        
        Args:
            action (int): Action to take
        """
        raise NotImplementedError()
    
    def _is_done(self, observations, fallen):
        """
        Check if episode is done
        
        Args:
            observations (np.array): Current observations
            fallen (bool): Whether the robot has fallen
            
        Returns:
            bool: True if done, False otherwise
        """
        raise NotImplementedError()
    
    def _compute_reward(self, observations, done, fallen):
        """
        Calculate reward
        
        Args:
            observations (np.array): Current observations
            done (bool): Done flag
            fallen (bool): Whether the robot has fallen
            
        Returns:
            float: Reward
        """
        raise NotImplementedError()
    
    def close(self):
        """
        Close the environment
        """
        # Clean up resources
        rospy.loginfo("Closing RobotGazeboEnv")
    
    def render(self, mode='human'):
        """
        Render the environment
        
        Args:
            mode (str): Rendering mode
        """
        # Rendering is handled by Gazebo
        pass

class MyGurdyWalkEnv(MyGurdySingleLegEnv):
    """
    Environment for training the Gurdy robot to walk
    """
    def __init__(self):
        """
        Initialize the Gurdy walk environment
        """
        super(MyGurdyWalkEnv, self).__init__()
        
        # Define action space
        self.action_space = spaces.Discrete(5)
        
        # Define observation space
        # Joint positions (6), linear speed, distance, head height
        low = np.array([-0.5, -0.5, -0.5, -0.5, -0.5, -0.5, 0.0, 0.0, 0.0])  
        high = np.array([0.5, 0.5, 0.5, 0.5, 0.5, 0.5, 2.0, 10.0, 1.0])
        self.observation_space = spaces.Box(low=low, high=high, dtype=np.float32)
        
        # Initialize state variables
        self.joint_positions = [0.0, 0.0, 0.0, 0.0, 0.0, 0.0]
        self.distance_moved = 0.0
        self.initial_height = 0.0  # Initial height of the robot
        
        rospy.logwarn("ACTION SPACES TYPE===>"+str(self.action_space))
        rospy.logwarn("OBSERVATION SPACES TYPE===>"+str(self.observation_space))
    
    def _set_init_pose(self):
        """Sets the Robot in its init pose"""
        # Initial position - centered joints
        initial_joints = [0.0, 0.0, 0.0, 0.0, 0.0, 0.0]
        self.move_joints(initial_joints)
        
        # Wait for the joints to settle
        time.sleep(0.1)
        
        # Store initial height
        if self._model_states:
            try:
                gurdy_index = self._model_states.name.index("gurdy")
                self.initial_height = self._model_states.pose[gurdy_index].position.z
                rospy.loginfo(f"Initial height of Gurdy: {self.initial_height}")
            except (ValueError, IndexError):
                self.initial_height = 0.18  # Default if not found
                rospy.logwarn("Could not determine initial height, using default")
    
    def _init_env_variables(self):
        """Initializes variables at the start of each episode"""
        # Reset state variables
        self.joint_positions = [0.0, 0.0, 0.0, 0.0, 0.0, 0.0]
        self.distance_moved = 0.0
        self._has_fallen = False
        
        # Store the start point
        self.start_point = self._odom.pose.pose.position
    
    def _set_action(self, action):
        """
        Convert actions to joint movements
        
        Args:
            action (int): Action index to execute
        """
        # Different tripod gaits for hexapod
        if action == 0:   # Tripod gait - set 1 forward, set 2 backward
            new_joints = [-0.3, 0.0, -0.3, 0.0, -0.3, 0.0]  # Legs 1,3,5 up, others normal
        elif action == 1: # Tripod gait - set 1 backward, set 2 forward
            new_joints = [0.0, -0.3, 0.0, -0.3, 0.0, -0.3]  # Legs 2,4,6 up, others normal
        elif action == 2: # Stand still
            new_joints = [0.0, 0.0, 0.0, 0.0, 0.0, 0.0]     # All legs neutral
        elif action == 3: # Wave pattern - front to back
            new_joints = [-0.3, -0.2, -0.1, 0.0, 0.0, 0.0]  # Wave pattern
        elif action == 4: # Wave pattern - back to front
            new_joints = [0.0, 0.0, 0.0, -0.1, -0.2, -0.3]  # Wave pattern
        
        # Execute joint movement
        self.move_joints(new_joints)
        self.joint_positions = new_joints
        
        # Wait for the robot to execute the movement
        time.sleep(0.1)
    
    def _get_obs(self):
        """
        Define robot observations
        
        Returns:
            np.array: [joint_angles, linear_speed, distance, head_height]
        """
        # Get joint angles
        joint_angles = self.get_joint_angles()
        
        # Get linear speed from odometry
        linear_speed = self.get_linear_speed()
        
        # Get distance from start point
        distance = self.get_distance_from_start_point(self.start_point)
        
        # Get head height
        head_height = self.head_height
        
        # Return observations: 6 joint positions + speed + distance + height
        return np.array([joint_angles[0], joint_angles[1], joint_angles[2], 
                         joint_angles[3], joint_angles[4], joint_angles[5],
                         linear_speed, distance, head_height])
    
    def _is_done(self, observations, fallen):
        """
        Determine if episode is complete
        
        Args:
            observations (np.array): Current observations
            fallen (bool): Whether the robot has fallen
            
        Returns:
            bool: True if done, False otherwise
        """
        # If robot has fallen, episode is done
        if fallen:
            rospy.logwarn("Episode done: Robot has fallen")
            return True
        
        # Extract distance from observations
        distance = observations[7]
        linear_speed = observations[6]
        
        # Check if maximum distance is reached
        if distance >= 5.0:
            rospy.loginfo("Episode done: Maximum distance reached")
            return True
        
        # Check if the robot is stuck (no movement for a long time)
        if linear_speed < 0.01 and self.cumulated_steps > 10:
            rospy.loginfo("Episode done: Robot is stuck")
            return True
        
        # Check for maximum number of steps
        if self.cumulated_steps >= 200:
            rospy.loginfo("Episode done: Maximum steps reached")
            return True
        
        return False
    
    def _compute_reward(self, observations, done, fallen):
        """
        Compute reward based on current state
        
        Args:
            observations (np.array): Current observations
            done (bool): Whether the episode is done
            fallen (bool): Whether the robot has fallen
            
        Returns:
            float: Calculated reward
        """
        # Extract values from observations
        linear_speed = observations[6]
        distance = observations[7]
        head_height = observations[8]
        
        # Big penalty if the robot has fallen
        if fallen:
            return -100.0
        
        # Reward for speed (forward movement)
        speed_reward = linear_speed
        
        # Reward for distance traveled
        distance_reward = 0.1 * distance
        
        # Reward for maintaining height (stability)
        height_ratio = head_height / max(0.01, self.initial_height)  # Avoid division by zero
        stability_reward = 5.0 * min(1.0, height_ratio)  # Cap at 1.0
        
        # Penalty for excessive joint movement (energy efficiency)
        energy_penalty = -0.05 * sum([abs(angle) for angle in observations[0:6]])
        
        # Penalty for episode ending with little distance
        terminal_penalty = 0
        if done and distance < 1.0 and not fallen:
            terminal_penalty = -1.0
        
        # Bonus for reaching the target
        completion_bonus = 0
        if done and distance >= 5.0:
            completion_bonus = 10.0
        
        # Calculate total reward
        reward = speed_reward + distance_reward + stability_reward + energy_penalty + terminal_penalty + completion_bonus
        
        return reward
    
    def get_joint_angles(self):
        """
        Retrieve joint angles from the robot's joint states
        
        Returns:
            list: Angles of all joints
        """
        joint_states = self._joint_states
        angles = [0.0, 0.0, 0.0, 0.0, 0.0, 0.0]  # Default zeros
        
        for i, name in enumerate(self.joint_names):
            for j, joint_name in enumerate(joint_states.name):
                if joint_name == name:
                    angles[i] = joint_states.position[j]
                    break
        
        return angles
    
    def get_linear_speed(self):
        """
        Retrieve linear speed from odometry
        
        Returns:
            float: Linear speed of the robot
        """
        if self._odom:
            return abs(self._odom.twist.twist.linear.x)
        return 0.0
    
    def get_distance_from_start_point(self, start_point):
        """
        Calculate distance from the start point
        
        Args:
            start_point (Point): The initial Point object
        
        Returns:
            float: Distance moved from the start point
        """
        current_position = self._odom.pose.pose.position
        dx = current_position.x - start_point.x
        dy = current_position.y - start_point.y
        
        # Calculate Euclidean distance
        distance = math.sqrt(dx*dx + dy*dy)
        return distance

# Register the environment
gym.envs.registration.register(
    id='MyGurdyWalkEnv-v0',
    entry_point='env:MyGurdyWalkEnv',
    max_episode_steps=200,
    reward_threshold=100.0,
)