import numpy as np
import matplotlib.pyplot as plt

n_states = 28
n_actions = 4 
goal_state = 27  

Q_table = np.zeros((n_states, n_actions))

learning_rate = 0.8
discount_factor = 0.95
exploration_prob = 0.2
epochs = 100

for epoch in range(epochs):
    current_state = np.random.randint(0, n_states)  
    if epoch % 10 == 0:
        print(f"Epoch {epoch}, Current Q-table snippet:")
        print(Q_table[24:28])  # Show states near goal
    while current_state != goal_state:
        if np.random.rand() < exploration_prob:
            action = np.random.randint(0, n_actions)  
        else:
            action = np.argmax(Q_table[current_state])  

        next_state = (current_state + 1) % n_states

        reward = 1 if next_state == goal_state else 0

        Q_table[current_state, action] += learning_rate * \
            (reward + discount_factor *
             np.max(Q_table[next_state]) - Q_table[current_state, action])

        current_state = next_state

q_values_grid = np.max(Q_table, axis=1).reshape((7, 4)) 

# Print learned Q-table
print("Learned Q-table:")
print(Q_table)

# Plot the grid of Q-values
plt.figure(figsize=(6,8))
plt.imshow(q_values_grid, cmap='coolwarm', interpolation='nearest')
plt.colorbar(label='Q-value')
plt.title('Learned Q-values for each state')
plt.xticks(np.arange(4), ['0', '1', '2', '3'])
plt.yticks(np.arange(7), ['0', '1', '2', '3', '4', '5', '6'])
plt.gca().invert_yaxis()  # To match grid layout
plt.grid(True)


# Annotating the Q-values on the grid
for i in range(7):
    for j in range(4):
        plt.text(j, i, f'{q_values_grid[i, j]:.2f}', ha='center', va='center', color='black')

plt.show()