from tqdm import tqdm
import numpy as np
import torch
import collections
import random
import pickle

class ReplayBuffer:
    def __init__(self, capacity):
        self.buffer = collections.deque(maxlen=capacity)
        self.capacity = capacity

    def add(self, state, action, reward, next_state, done):
        self.buffer.append((state, action, reward, next_state, done))

    def sample(self, batch_size):
        transitions = random.sample(self.buffer, batch_size)
        state, action, reward, next_state, done = zip(*transitions)
        return np.array(state), action, reward, np.array(next_state), done

    def size(self):
        return len(self.buffer)

    def clear_half_old(self):
        # 将 deque 转换为 list 后再进行切片
        if len(self.buffer) == self.capacity:
            buffer_list = list(self.buffer)
            new_size = len(buffer_list) // 2
            self.buffer = collections.deque(buffer_list[-new_size:], maxlen=self.capacity)

    def clear_all(self):
        self.buffer = collections.deque(maxlen=self.capacity)

    def save(self, file_path):
        with open(file_path, 'wb') as f:
            pickle.dump(list(self.buffer), f)

    def load(self, file_path):
        print('load replay buffer')
        with open(file_path, 'rb') as f:
            data = pickle.load(f)
            self.buffer = collections.deque(data, maxlen=self.capacity)

def old_moving_average(a, window_size):
    cumulative_sum = np.cumsum(np.insert(a, 0, 0))
    middle = (cumulative_sum[window_size:] - cumulative_sum[:-window_size]) / window_size
    r = np.arange(1, window_size - 1, 2)
    begin = np.cumsum(a[:window_size - 1])[::2] / r
    end = (np.cumsum(a[:-window_size:-1])[::2] / r)[::-1]
    return np.concatenate((begin, middle, end))

def moving_average(a, window_size):
    """
    计算移动平均，支持任何窗口大小，并自动处理边缘对齐
    """
    window_size = int(window_size)
    if window_size <= 1:
        return a
    n = len(a)
    if n == 0:
        return a
    # 使用卷积计算总和
    kernel = np.ones(window_size)
    # mode='same' 保证输出长度与输入一致
    sum_a = np.convolve(a, kernel, mode='same')
    # 计算每个位置实际参与求和的元素个数（用于修正边缘）
    counts = np.convolve(np.ones(n), kernel, mode='same')
    return sum_a / counts

def ema(a, epsilon):
    # epsilon越大，越趋向于最新的数据
    ema_list = []
    v = 0
    for t, x in enumerate(a, 1):
        v = (1 - epsilon) * v + epsilon * x
        # 偏差修正：根据样本数进行缩放，防止初始值趋向于0
        v_corrected = v / (1 - (1 - epsilon)**t)
        ema_list.append(v_corrected)
    return np.array(ema_list)

def train_on_policy_agent(env, agent, num_episodes):
    return_list = []
    for i in range(10):
        with tqdm(total=int(num_episodes / 10), desc='Iteration %d' % i) as pbar:
            for i_episode in range(int(num_episodes / 10)):
                episode_return = 0
                transition_dict = {'states': [], 'actions': [], 'next_states': [], 'rewards': [], 'dones': []}
                state = env.reset()
                done = False
                while not done:
                    action = agent.take_action(state)
                    next_state, reward, done, _ = env.step(action, )
                    transition_dict['states'].append(state)
                    transition_dict['actions'].append(action)
                    transition_dict['next_states'].append(next_state)
                    transition_dict['rewards'].append(reward)
                    transition_dict['dones'].append(done)
                    state = next_state
                    episode_return += reward
                return_list.append(episode_return)
                agent.update(transition_dict)
                if (i_episode + 1) % 10 == 0:
                    pbar.set_postfix({'episode': '%d' % (num_episodes / 10 * i + i_episode + 1),
                                      'return': '%.3f' % np.mean(return_list[-10:])})
                pbar.update(1)
    return return_list


def train_off_policy_agent(env, agent, num_episodes, replay_buffer, minimal_size, batch_size):
    return_list = []
    for i in range(10):  # 10
        with tqdm(total=int(num_episodes / 10), desc='Iteration %d' % i) as pbar:  # 进度条
            for i_episode in range(int(num_episodes / 10)):
                episode_return = 0
                state = env.reset()
                done = False
                while not done:
                    # 执行动作得到环境反馈
                    action = agent.take_action(state)
                    next_state, reward, done, _ = env.step(action, )  # pendulum中的action一定要是ndarray才能输入吗？
                    # 运行记录添加回放池
                    replay_buffer.add(state, action, reward, next_state, done)
                    state = next_state
                    episode_return += reward
                    # 从回放池采样更新智能体
                    if replay_buffer.size() > minimal_size:
                        b_s, b_a, b_r, b_ns, b_d = replay_buffer.sample(batch_size)
                        transition_dict = {'states': b_s, 'actions': b_a, 'next_states': b_ns, 'rewards': b_r,
                                           'dones': b_d}
                        agent.update(transition_dict)
                return_list.append(episode_return)
                if (i_episode + 1) % 10 == 0:
                    pbar.set_postfix({'episode': '%d' % (num_episodes / 10 * i + i_episode + 1),
                                      'return': '%.3f' % np.mean(return_list[-10:])})
                pbar.update(1)
    return return_list


def compute_advantage(gamma, lmbda, td_delta):
    td_delta = td_delta.detach().numpy()
    advantage_list = []
    advantage = 0.0
    for delta in td_delta[::-1]:
        advantage = gamma * lmbda * advantage + delta
        advantage_list.append(advantage)
    advantage_list.reverse()
    return torch.tensor(advantage_list, dtype=torch.float)
