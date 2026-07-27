# Flash-Fusion Benchmark Report

Generated: 2026-07-27T00:42:28+00:00

## Summary Table

| Baseline   |   Avg LLM Accuracy |   Avg Latency (s) |   Avg Cost (USD) |
|:-----------|-------------------:|------------------:|-----------------:|
| REACT_ONLY |             1.0000 |           15.4210 |           0.0009 |

## Per-Query Results

### Q13: Sort all bus rows by timestamp in ascending order. Use the first 80% of rows for training and the final 20% as the chronological holdout. Train a logistic regression model using the acceleration features. Predict the label in the behavior column for the first row in the holdout set.

#### REACT_ONLY

**Answer:** The predicted label for the first row in the holdout set is: moderate.

- Executed: True | Rejected: False | Judge: N/A
- Stages: react_agent
- Latency: 13.90s | Cost: $0.00092

**Agent Trace**

```
Thought: Attempt 1: generate executable pandas code
Action: python_exec
Action Input: import pandas as pd
from sklearn.model_selection import train_test_split
from sklearn.linear_model import LogisticRegression

# Sort the DataFrame by timestamp
df = df.sort_values(by='timestamp')

# Split the data into training and holdout sets
train_size = int(len(df) * 0.8)
train_df, holdout_df = df[:train_size], df[train_size:]

# Define the features and target
X_train = train_df[['accel_mean', 'accel_variance', 'accel_stats_x_p1', 'accel_stats_x_p10', 'accel_stats_x_p90', 'accel_stats_x_p99', 
                    'accel_stats_y_p1', 'accel_stats_y_p10', 'accel_stats_y_p90', 'accel_stats_y_p99', 'accel_stats_z_p1', 'accel_stats_z_p10', 
                    'accel_stats_z_p90', 'accel_stats_z_p99', 'extreme_event_magnitude', 'instability_score']]
y_train = train_df['behavior']
X_holdout = holdout_df[['accel_mean', 'accel_variance', 'accel_stats_x_p1', 'accel_stats_x_p10', 'accel_stats_x_p90', 'accel_stats_x_p99', 
                        'accel_stats_y_p1', 'accel_stats_y_p10', 'accel_stats_y_p90', 'accel_stats_y_p99', 'accel_stats_z_p1', 'accel_stats_z_p10', 
                        'accel_stats_z_p90', 'accel_stats_z_p99', 'extreme_event_magnitude', 'instability_score']]

# Train a logistic regression model
model = LogisticRegression(max_iter=1000)
model.fit(X_train, y_train)

# Predict the label for the first row in the holdout set
result = model.predict(X_holdout.head(1))
Observation: ['moderate']
Final Answer: The predicted label for the first row in the holdout set is: moderate.
```

**Final Code Executed**

```python
import pandas as pd
from sklearn.model_selection import train_test_split
from sklearn.linear_model import LogisticRegression

# Sort the DataFrame by timestamp
df = df.sort_values(by='timestamp')

# Split the data into training and holdout sets
train_size = int(len(df) * 0.8)
train_df, holdout_df = df[:train_size], df[train_size:]

# Define the features and target
X_train = train_df[['accel_mean', 'accel_variance', 'accel_stats_x_p1', 'accel_stats_x_p10', 'accel_stats_x_p90', 'accel_stats_x_p99', 
                    'accel_stats_y_p1', 'accel_stats_y_p10', 'accel_stats_y_p90', 'accel_stats_y_p99', 'accel_stats_z_p1', 'accel_stats_z_p10', 
                    'accel_stats_z_p90', 'accel_stats_z_p99', 'extreme_event_magnitude', 'instability_score']]
y_train = train_df['behavior']
X_holdout = holdout_df[['accel_mean', 'accel_variance', 'accel_stats_x_p1', 'accel_stats_x_p10', 'accel_stats_x_p90', 'accel_stats_x_p99', 
                        'accel_stats_y_p1', 'accel_stats_y_p10', 'accel_stats_y_p90', 'accel_stats_y_p99', 'accel_stats_z_p1', 'accel_stats_z_p10', 
                        'accel_stats_z_p90', 'accel_stats_z_p99', 'extreme_event_magnitude', 'instability_score']]

# Train a logistic regression model
model = LogisticRegression(max_iter=1000)
model.fit(X_train, y_train)

# Predict the label for the first row in the holdout set
result = model.predict(X_holdout.head(1))
```

---

### Q14: Sort all bus rows by timestamp in ascending order. Use the first 80% of rows for training and the final 20% as the chronological holdout. Train a random forest model using the acceleration features. Predict the label in the behavior column for the first row in the holdout set.

#### REACT_ONLY

**Answer:** The predicted label for the first row in the holdout set is: moderate

- Executed: True | Rejected: False | Judge: N/A
- Stages: react_agent
- Latency: 28.31s | Cost: $0.00092

**Agent Trace**

```
Thought: Attempt 1: generate executable pandas code
Action: python_exec
Action Input: import pandas as pd
from sklearn.ensemble import RandomForestClassifier
from sklearn.model_selection import train_test_split

# Sort the DataFrame by timestamp
df = df.sort_values(by='timestamp')

# Split the data into training and holdout sets
train_size = int(len(df) * 0.8)
train_df, holdout_df = df[:train_size], df[train_size:]

# Define the features and target
X_train = train_df[['accel_mean', 'accel_variance', 'accel_stats_x_p1', 'accel_stats_x_p10', 'accel_stats_x_p90', 'accel_stats_x_p99', 
                    'accel_stats_y_p1', 'accel_stats_y_p10', 'accel_stats_y_p90', 'accel_stats_y_p99', 
                    'accel_stats_z_p1', 'accel_stats_z_p10', 'accel_stats_z_p90', 'accel_stats_z_p99']]
y_train = train_df['behavior']

X_holdout = holdout_df[['accel_mean', 'accel_variance', 'accel_stats_x_p1', 'accel_stats_x_p10', 'accel_stats_x_p90', 'accel_stats_x_p99', 
                        'accel_stats_y_p1', 'accel_stats_y_p10', 'accel_stats_y_p90', 'accel_stats_y_p99', 
                        'accel_stats_z_p1', 'accel_stats_z_p10', 'accel_stats_z_p90', 'accel_stats_z_p99']]
y_holdout = holdout_df['behavior']

# Train a random forest model
model = RandomForestClassifier(n_estimators=100)
model.fit(X_train, y_train)

# Predict the label for the first row in the holdout set
first_row_holdout = X_holdout.iloc[0].values.reshape(1, -1)
prediction = model.predict(first_row_holdout)

result = prediction[0]
Observation: moderate
Final Answer: The predicted label for the first row in the holdout set is: moderate
```

**Final Code Executed**

```python
import pandas as pd
from sklearn.ensemble import RandomForestClassifier
from sklearn.model_selection import train_test_split

# Sort the DataFrame by timestamp
df = df.sort_values(by='timestamp')

# Split the data into training and holdout sets
train_size = int(len(df) * 0.8)
train_df, holdout_df = df[:train_size], df[train_size:]

# Define the features and target
X_train = train_df[['accel_mean', 'accel_variance', 'accel_stats_x_p1', 'accel_stats_x_p10', 'accel_stats_x_p90', 'accel_stats_x_p99', 
                    'accel_stats_y_p1', 'accel_stats_y_p10', 'accel_stats_y_p90', 'accel_stats_y_p99', 
                    'accel_stats_z_p1', 'accel_stats_z_p10', 'accel_stats_z_p90', 'accel_stats_z_p99']]
y_train = train_df['behavior']

X_holdout = holdout_df[['accel_mean', 'accel_variance', 'accel_stats_x_p1', 'accel_stats_x_p10', 'accel_stats_x_p90', 'accel_stats_x_p99', 
                        'accel_stats_y_p1', 'accel_stats_y_p10', 'accel_stats_y_p90', 'accel_stats_y_p99', 
                        'accel_stats_z_p1', 'accel_stats_z_p10', 'accel_stats_z_p90', 'accel_stats_z_p99']]
y_holdout = holdout_df['behavior']

# Train a random forest model
model = RandomForestClassifier(n_estimators=100)
model.fit(X_train, y_train)

# Predict the label for the first row in the holdout set
first_row_holdout = X_holdout.iloc[0].values.reshape(1, -1)
prediction = model.predict(first_row_holdout)

result = prediction[0]
```

---

### Q15: Sort all bus rows by timestamp in ascending order. Use the first 80% of rows for training and the final 20% as the chronological holdout. Train a 1-nearest-neighbor model using the acceleration features. Predict the label in the behavior column for the first row in the holdout set.

#### REACT_ONLY

**Answer:** The predicted label for the first row in the holdout set is: moderate

- Executed: True | Rejected: False | Judge: N/A
- Stages: react_agent
- Latency: 8.97s | Cost: $0.00094

**Agent Trace**

```
Thought: Attempt 1: generate executable pandas code
Action: python_exec
Action Input: import pandas as pd
from sklearn.model_selection import train_test_split
from sklearn.neighbors import KNeighborsClassifier

# Sort the DataFrame by timestamp
df = df.sort_values(by='timestamp')

# Split the data into training and holdout sets
train_size = int(len(df) * 0.8)
train_df, holdout_df = df[:train_size], df[train_size:]

# Define the features and target
X_train = train_df[['accel_mean', 'accel_variance', 'accel_stats_x_p1', 'accel_stats_x_p10', 'accel_stats_x_p90', 'accel_stats_x_p99', 
                    'accel_stats_y_p1', 'accel_stats_y_p10', 'accel_stats_y_p90', 'accel_stats_y_p99', 
                    'accel_stats_z_p1', 'accel_stats_z_p10', 'accel_stats_z_p90', 'accel_stats_z_p99', 
                    'extreme_event_magnitude', 'instability_score']]
y_train = train_df['behavior']

X_holdout = holdout_df[['accel_mean', 'accel_variance', 'accel_stats_x_p1', 'accel_stats_x_p10', 'accel_stats_x_p90', 'accel_stats_x_p99', 
                        'accel_stats_y_p1', 'accel_stats_y_p10', 'accel_stats_y_p90', 'accel_stats_y_p99', 
                        'accel_stats_z_p1', 'accel_stats_z_p10', 'accel_stats_z_p90', 'accel_stats_z_p99', 
                        'extreme_event_magnitude', 'instability_score']]

# Train a 1-nearest-neighbor model
knn = KNeighborsClassifier(n_neighbors=1)
knn.fit(X_train, y_train)

# Predict the label for the first row in the holdout set
result = knn.predict(X_holdout.head(1))
Observation: ['moderate']
Final Answer: The predicted label for the first row in the holdout set is: moderate
```

**Final Code Executed**

```python
import pandas as pd
from sklearn.model_selection import train_test_split
from sklearn.neighbors import KNeighborsClassifier

# Sort the DataFrame by timestamp
df = df.sort_values(by='timestamp')

# Split the data into training and holdout sets
train_size = int(len(df) * 0.8)
train_df, holdout_df = df[:train_size], df[train_size:]

# Define the features and target
X_train = train_df[['accel_mean', 'accel_variance', 'accel_stats_x_p1', 'accel_stats_x_p10', 'accel_stats_x_p90', 'accel_stats_x_p99', 
                    'accel_stats_y_p1', 'accel_stats_y_p10', 'accel_stats_y_p90', 'accel_stats_y_p99', 
                    'accel_stats_z_p1', 'accel_stats_z_p10', 'accel_stats_z_p90', 'accel_stats_z_p99', 
                    'extreme_event_magnitude', 'instability_score']]
y_train = train_df['behavior']

X_holdout = holdout_df[['accel_mean', 'accel_variance', 'accel_stats_x_p1', 'accel_stats_x_p10', 'accel_stats_x_p90', 'accel_stats_x_p99', 
                        'accel_stats_y_p1', 'accel_stats_y_p10', 'accel_stats_y_p90', 'accel_stats_y_p99', 
                        'accel_stats_z_p1', 'accel_stats_z_p10', 'accel_stats_z_p90', 'accel_stats_z_p99', 
                        'extreme_event_magnitude', 'instability_score']]

# Train a 1-nearest-neighbor model
knn = KNeighborsClassifier(n_neighbors=1)
knn.fit(X_train, y_train)

# Predict the label for the first row in the holdout set
result = knn.predict(X_holdout.head(1))
```

---

### Q16: Sort all bus rows by timestamp in ascending order. Use the first 80% of rows for training and the final 20% as the chronological holdout. Train a hist gradient boosting model using the acceleration features. Predict the label in the behavior column for the first row in the holdout set.

#### REACT_ONLY

**Answer:** The predicted label for the first row in the holdout set is: moderate

- Executed: True | Rejected: False | Judge: N/A
- Stages: react_agent
- Latency: 10.51s | Cost: $0.00092

**Agent Trace**

```
Thought: Attempt 1: generate executable pandas code
Action: python_exec
Action Input: import pandas as pd
from sklearn.model_selection import train_test_split
from sklearn.ensemble import HistGradientBoostingClassifier
from sklearn.metrics import accuracy_score

# Sort the DataFrame by timestamp
df = df.sort_values(by='timestamp')

# Split the data into training and holdout sets
train_size = int(0.8 * len(df))
train_df, holdout_df = df[:train_size], df[train_size:]

# Define the features and target
X_train = train_df[['accel_mean', 'accel_variance', 'accel_stats_x_p1', 'accel_stats_x_p10', 'accel_stats_x_p90', 'accel_stats_x_p99', 
                    'accel_stats_y_p1', 'accel_stats_y_p10', 'accel_stats_y_p90', 'accel_stats_y_p99', 'accel_stats_z_p1', 'accel_stats_z_p10', 
                    'accel_stats_z_p90', 'accel_stats_z_p99', 'extreme_event_magnitude', 'instability_score']]
y_train = train_df['behavior']

X_holdout = holdout_df[['accel_mean', 'accel_variance', 'accel_stats_x_p1', 'accel_stats_x_p10', 'accel_stats_x_p90', 'accel_stats_x_p99', 
                        'accel_stats_y_p1', 'accel_stats_y_p10', 'accel_stats_y_p90', 'accel_stats_y_p99', 'accel_stats_z_p1', 'accel_stats_z_p10', 
                        'accel_stats_z_p90', 'accel_stats_z_p99', 'extreme_event_magnitude', 'instability_score']]

# Train a HistGradientBoostingClassifier model
model = HistGradientBoostingClassifier()
model.fit(X_train, y_train)

# Predict the label for the first row in the holdout set
prediction = model.predict(X_holdout.head(1))

result = prediction[0]
Observation: moderate
Final Answer: The predicted label for the first row in the holdout set is: moderate
```

**Final Code Executed**

```python
import pandas as pd
from sklearn.model_selection import train_test_split
from sklearn.ensemble import HistGradientBoostingClassifier
from sklearn.metrics import accuracy_score

# Sort the DataFrame by timestamp
df = df.sort_values(by='timestamp')

# Split the data into training and holdout sets
train_size = int(0.8 * len(df))
train_df, holdout_df = df[:train_size], df[train_size:]

# Define the features and target
X_train = train_df[['accel_mean', 'accel_variance', 'accel_stats_x_p1', 'accel_stats_x_p10', 'accel_stats_x_p90', 'accel_stats_x_p99', 
                    'accel_stats_y_p1', 'accel_stats_y_p10', 'accel_stats_y_p90', 'accel_stats_y_p99', 'accel_stats_z_p1', 'accel_stats_z_p10', 
                    'accel_stats_z_p90', 'accel_stats_z_p99', 'extreme_event_magnitude', 'instability_score']]
y_train = train_df['behavior']

X_holdout = holdout_df[['accel_mean', 'accel_variance', 'accel_stats_x_p1', 'accel_stats_x_p10', 'accel_stats_x_p90', 'accel_stats_x_p99', 
                        'accel_stats_y_p1', 'accel_stats_y_p10', 'accel_stats_y_p90', 'accel_stats_y_p99', 'accel_stats_z_p1', 'accel_stats_z_p10', 
                        'accel_stats_z_p90', 'accel_stats_z_p99', 'extreme_event_magnitude', 'instability_score']]

# Train a HistGradientBoostingClassifier model
model = HistGradientBoostingClassifier()
model.fit(X_train, y_train)

# Predict the label for the first row in the holdout set
prediction = model.predict(X_holdout.head(1))

result = prediction[0]
```

---
