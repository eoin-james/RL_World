import gym

# import MODEL
MODEL = None

env_name = ""
env = gym.make(env_name)

model = MODEL(env)

model.learn(total_timesteps=10_000)

obs = env.reset()
for i in range(1000):
    action, _states = model.predict(obs, deterministic=True)
    obs, reward, done, info = env.step(action)
    env.render()
    if done:
      obs = env.reset()

env.close()