import cv2
import time
import pickle
import numpy             as np
import matplotlib.pyplot as plt

from PIL        import Image
from matplotlib import style

style.use('ggplot')

SIZE          = 10
MOVE_PENALTY  = 1
FOOD_REWARD   = 25
ENEMY_PENELTY = 300
LOG_FREQUENCY = 3000
EPOCHS        = 50000

epsilon       = .9
EPS_DECAY     = .9998

# start_q_table = None # or filename
start_q_table = 'qtable-1560462324.pickle'

LEARNING_RATE = 0.1
DISCOUNT      = 0.95

PLAYER_N = 1
FOOD_N = 2
ENEMY_N = 3

entity_dict = { #colors
  1:(255,175,0), #player = blue
  2: (0,255,0),  #food = green
  3: (0,0,255)}  #enemy = red

class Blob:
  def __init__(self):
    self.x = np.random.randint(0, SIZE)
    self.y = np.random.randint(0, SIZE)
  
  def __str__(self):
    return f'{self.x}, {self.y}'
  
  def __sub__(self, other):
    return (self.x - other.x, self.y - other.y)

  def action(self, choice):
    if choice == 0:
      self.move(x=1,  y=1)
    if choice == 1:
      self.move(x=-1, y=-1)
    if choice == 2:
      self.move(x=-1, y=1)
    if choice == 3:
      self.move(x=1,  y=-1)
  
  def move(self, x=False, y=False):
    if not x:
      self.x += np.random.randint(-1, 2)
    else:
      self.x += x
    if not y:
      self.y += np.random.randint(-1, 2)
    else:
      self.y += y
    
    if self.x < 0:
      self.x = 0
    elif self.x > SIZE - 1:
      self.x = SIZE - 1
    
    if self.y < 0:
      self.y = 0
    elif self.y > SIZE - 1:
      self.y = SIZE - 1

if start_q_table is None:
  q_table = {}
  for x1 in range(-SIZE+1, SIZE):
    for y1 in range(-SIZE+1, SIZE):
      for x2 in range(-SIZE+1, SIZE):
        for y2 in range(-SIZE+1, SIZE):
          q_table[((x1, y1),(x2, y2))] = [np.random.uniform(-5, 0) for i in range(4)]
else:
  with open(start_q_table, 'rb') as f:
    q_table = pickle.load(f)

episode_rewards = []
for epoch in range(EPOCHS):
  player = Blob()
  food   = Blob()
  enemy  = Blob()

  if epoch % LOG_FREQUENCY == 0:
    print(f'on # {epoch}, epsilon: {epsilon}')
    print(f'{LOG_FREQUENCY} ep mean {np.mean(episode_rewards[-LOG_FREQUENCY:])}')
    show = True
  else:
    show = False

  episode_reward = 0
  for i in range(500): #steps
    obs = (player-food, player-enemy)
    if np.random.random() > epsilon:
      action = np.argmax(q_table[obs])
    else:
      action = np.random.randint(0, 4)
    
    player.action(action)

    ###maybe later
    enemy.move()
    food.move()
    ###

    if (player.x, player.y) == (enemy.x, enemy.y):
      reward = -ENEMY_PENELTY
    elif (player.x, player.y) == (food.x, food.y):
      reward = FOOD_REWARD
    else:
      reward = -MOVE_PENALTY
    
    new_obs = (player-food, player-enemy)
    max_future_q = np.max(q_table[new_obs])
    current_q = q_table[obs][action]

    if reward == FOOD_REWARD:
      new_q = FOOD_REWARD
    elif reward == -ENEMY_PENELTY:
      new_q = -ENEMY_PENELTY
    else:
      new_q = (1-LEARNING_RATE)*current_q + LEARNING_RATE * (reward + DISCOUNT * max_future_q)

    q_table[obs][action] = new_q

    if show:
      env = np.zeros((SIZE, SIZE, 3), dtype=np.uint8)
      env[food.y  ][food.x  ] =  entity_dict[FOOD_N  ]
      env[enemy.y ][enemy.x ] =  entity_dict[ENEMY_N ]
      env[player.y][player.x] =  entity_dict[PLAYER_N]

      img = Image.fromarray(env, 'RGB')
      img = img.resize((300,300))
      cv2.imshow('', np.array(img))
      if reward == FOOD_REWARD or reward == -ENEMY_PENELTY:
        if cv2.waitKey(500) & 0XFF == ord('q'):
          break
      else:
        if cv2.waitKey(50) & 0XFF == ord('q'):
          break

    episode_reward += reward
    if reward == FOOD_REWARD or reward == -ENEMY_PENELTY:
      break
  
  episode_rewards.append(episode_reward)
  epsilon *= EPS_DECAY

moving_avg = np.convolve(episode_rewards, np.ones((LOG_FREQUENCY, )) / LOG_FREQUENCY, mode='valid')

plt.plot([i for i in range(len(moving_avg))], moving_avg)
plt.ylabel(f'reward {LOG_FREQUENCY}MA')
plt.xlabel('Episode #')
plt.show()

with open (f'qtable-{int(time.time())}.pickle', 'wb') as f:
  pickle.dump(q_table, f)