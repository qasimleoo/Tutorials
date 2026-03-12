


SCIKIT-LEARN is like a magic toolbox full of tools that help you teach computers how to learn from data and make some smart decisions - just like we learn from expiriences,

Simplifies implementing standard ML models like Classification, Regression, clustering, and dimensionality reduction,

Widly used in industry and academics.

Covers almost every classical model.


---

The top machine learning (ML) algorithms fall into three main categories: supervised, unsupervised, and reinforcement learning. The choice of algorithm depends on the task and data characteristics. 
GeeksforGeeks
GeeksforGeeks
 +2
Supervised Learning
Supervised learning algorithms use labeled data to learn a function that maps inputs to outputs for tasks like classification and regression. 
GeeksforGeeks
GeeksforGeeks
 +1
Linear Regression: Models the linear relationship between input and a continuous output variable (e.g., predicting house prices based on size).
Logistic Regression: Used for binary classification, predicting the probability of an event (e.g., whether an email is spam or not).
Decision Trees: Splits data into branches based on features, forming a tree-like structure for decision-making. They are easy to interpret.
Support Vector Machines (SVM): Finds the optimal hyperplane (decision boundary) that maximizes the margin between different classes of data, particularly effective in high-dimensional spaces.
K-Nearest Neighbors (KNN): Classifies a data point based on the majority class of its 'K' nearest neighbors, simple and effective for pattern recognition and recommendation systems.
Naïve Bayes: A probabilistic classifier based on Bayes' theorem, assuming independence between features. It works well for large datasets and is often used in text classification and sentiment analysis. 
Built In | Tech Jobs
Built In | Tech Jobs
 +6
Unsupervised Learning
Unsupervised learning algorithms work with unlabeled data to discover hidden patterns or structures without predefined outputs. 
GeeksforGeeks
GeeksforGeeks
 +1
K-Means Clustering: Groups data points into a specified number ('K') of clusters based on similarity. Common uses include customer segmentation and image compression.
Principal Component Analysis (PCA): A dimensionality reduction technique that transforms variables into a smaller set of uncorrelated components, useful for simplifying data analysis and visualization.
Apriori: An algorithm for association rule mining, used to discover frequent itemsets and the relationships between them in large databases (e.g., market basket analysis). 
Coursera
Coursera
 +4
Ensemble Methods and Neural Networks
These advanced techniques combine multiple models or use complex structures to improve performance. 
Random Forest: An ensemble method that builds multiple decision trees on random subsets of data and merges their predictions through voting to reduce overfitting and improve accuracy.
Gradient Boosting (e.g., XGBoost, LightGBM, CatBoost): Builds models sequentially, where each new model corrects the errors made by previous ones. These are highly accurate and widely used in competitive ML tasks and fraud detection.
Artificial Neural Networks (ANNs): Inspired by the human brain, these use layers of interconnected nodes to model complex patterns, forming the foundation of deep learning for image/speech recognition and natural language processing. 
Coursera
Coursera
 +4
Choosing an Algorithm
There is no single "best" algorithm for all problems. Factors to consider when selecting one include: 
Built In | Tech Jobs
Built In | Tech Jobs
The type of task (classification, regression, clustering, etc.)
The size and quality of the dataset
The need for model interpretability
Available computational resources 
Prismatic Technologies
Prismatic Technologies
 +1
Experimentation with different algorithms is crucial to determine the most effective approach for a specific problem. 
SAS: Data and AI Solutions
SAS: Data and AI Solutions

---

---
---
---
---


# Machine Learning and Data Science: 
Understand Business Problems ->
Data Collection (Big Data) -> 
Data Cleaning and Exploration -> 
Build Model (Forecasting) -> 
Collect Insights

--- 

To teach AI we have below learning methods to make it more accuratre and more efficient

## Supervised ML
- Cat images (Label all as Cats)
- Birds images (Label all as Birds)
Computer will create a pattern based on it and next time you give an image it will recognize it (on error we give it a message and it learns on it and increases accuracy)
another example is: Voting polls
algo types: Naire Bayes algo (Input -> Model -> Output)
Teaching someone by showing some examples: e.g., Ball types, Email Spam detection

### Two types: 
Classification and Regression
i. Classification: predefined categories .. KNN, Logistic regression, Decision Tress, Supper Machines, Neural Networks are commonly used 
Algo Used:
Logistic Regression, Decision Trees, Support Vector Machines (SVM), k-Nearest Neighbors (k-NN), Naive Bayes, Random Forests.

Use Cases:
- Email spam detection, medical diagnosis, fraud detection, sentiment analysis, image recognition.	

ii. Regression: for numerical data based on input features
Algo used:
Linear Regression, Polynomial Regression, Ridge Regression, Lasso Regression, Regression Trees, Random Forests.
Use cases:
- House price prediction, weather forecasting, financial forecasting, sales prediction, risk estimation.

Classification predicts discrete, categorical labels, while regression predicts continuous, numerical values


## Un-Supervised ML (used mostly because supervised needs labelign and classifications)
No supervisor .. no labeling no classification.. 
here we have raw data
Marble images to machine (you know that but machine doesn't)
Pattern will be made randomly .. based on all images feeded like based on colors .. based on texture.. based on sizes.. 
can make further groups as in nested groups 
PK movies main character is the best exampels.. 
Benefits:
ease on ... hidden relationships, hidden structure.. future predicitions
Algo: Clustering -> K-mean 


## Reinforcement Learning
Trial and error based 
wanna teacha a Pet robot .. some tricks .. like reward/positive signals/negative signals..
Reward and Punish/Penalty process .. 
use cases (robots trainign, gaming characters)
Algo: Q-learning

Agent -> Actions -> Environment 
		Reward/State <-
Next time it learns and behaves differently


## Semi-Supervised ML (positive poiints or SML and USML)
a machine trained on 10 cat vs 10000 cats images 
2nd one will be much accurate based on more traning data
may have raw data and labeled data .. 
based on labeled data it makes clusters (own as well as based on labels) in unsupervised data 
youtube channels (10000 labeled vs 100000 non-labled) .. SSML will make clusters based on 10k labled data

--- 

## Intro to Regression with real life example:
Regression is a statistical method that helps us to understand and predict relationship between variables (a value/a quantitative data)
- how one variable (dependent) changes as another independent variable chnages.. predict dependent based on independent one
like predict salary based on the years of expirience, exam scores based on study hours, resale price of a vehicle based on its age
			|
			|
			|
			|
			|
  	 Y      |
(dependent)	|
			|
			───────────────────────
		X (independent)

┌──────────────────────┬─────────────┬─────────────────────┐
│    Regression Type   │    Shape    │     Best For        │
├──────────────────────┼─────────────┼─────────────────────┤
│ Positive Linear      │ ↗  Line     │ Proportional growth │
│ Negative Linear      │ ↘  Line     │ Inverse relation    │
│ Polynomial (Quad)    │ ∪ or ∩      │ Curved patterns     │
│ Polynomial (Cubic)   │ ~ S-wave    │ Inflection points   │
│ Logarithmic          │ ╭── flatten │ Diminishing returns │
│ Exponential Growth   │ ──╮ steep   │ Rapid growth        │
│ Exponential Decay    │ ╲__ flatten │ Radioactive decay   │
│ Logistic (Sigmoid)   │ S-curve 0→1 │ Classification      │
│ Power                │ Curved up   │ Scaling laws        │
│ Ridge / Lasso        │ Line (reg.) │ Overfitting control │
└──────────────────────┴─────────────┴─────────────────────┘

1. POSITIVE LINEAR          2. NEGATIVE LINEAR
   Y                           Y
   │    ·  ·                   │·  ·
   │  ·                        │   ·
   │·                          │     ·
   └────── X                   └────── X
   y = mx + b (m > 0)          y = mx + b (m < 0)


3. POLYNOMIAL (QUAD)        4. POLYNOMIAL (CUBIC)
   Y                           Y
   │·      ·                   │      · ·
   │ ·    ·                    │    ·
   │  · ·                      │  ·
   └────── X                   │· ·
   y = ax² + bx + c            └────── X
                               y = ax³ + bx² + cx + d


5. LOGARITHMIC              6. EXPONENTIAL GROWTH
   Y                           Y
   │    · · · ·                │        ·
   │  ·                        │      ·
   │ ·                         │   ·
   │·                          │· ·
   └────── X                   └────── X
   y = a·ln(x) + b             y = a·eᵇˣ


7. EXPONENTIAL DECAY        8. LOGISTIC (SIGMOID)
   Y                           Y
   │·                         1│    · · ·
   │ ·                         │  ·
   │  ·                        │ ·
   │    · · ·                 0│·
   └────── X                   └────── X
   y = a·e⁻ᵇˣ                  y = 1/(1 + e⁻ˣ)


9. POWER                    10. RIDGE/LASSO
   Y                            Y
   │      ·                     │    · /
   │    ·                       │  · / ← regular
   │  ·                         │· / ← ridge
   │·                           └────── X
   └────── X                    (regularized linear)
   y = a·xᵇ


------------------------------------------------------------

Supervised -> Classification -> Linear Regression
Linear Regression:

Equation: y = mx + b
relationship between 2 variables (independent and dependent)
y -> dependent
x -> independent
m -> slope of the line (how much does y change for a unit of x)
b -> intercept (value of y when x is 0)

Project: Predicting pizza prices
Step1: Data Collection
Step2: Calculation
Step3: Prediciton
Step4: Visualization

i. 
┌──────────┬────────────┬────────────┐
│ Pizza    │ Diameter   │   Price    │
│  Size    │   (cm)     │   ($)      │
├──────────┼────────────┼────────────┤
│ Small    │    20      │    8       │
│ Medium   │    30      │    12      │
│ Large    │    40      │    16      │
└──────────┴────────────┴────────────┘


┌─────┬─────┬──────────┬──────────┬────────────┬────────────┐
│  X  │  Y  │  (X-X̄)   │  (Y-Ȳ)   │  (X-X̄)(Y-Ȳ)│  (X-X̄)²    │
├─────┼─────┼──────────┼──────────┼────────────┼────────────┤
│ 20  │  8  │ 20-30=-10│  8-12=-4 │ (-10)(-4)  │ (-10)²     │
│     │     │          │          │    = 40    │   = 100    │
├─────┼─────┼──────────┼──────────┼────────────┼────────────┤
│ 30  │ 12  │ 30-30= 0 │ 12-12= 0 │  (0)(0)    │  (0)²      │
│     │     │          │          │    = 0     │   = 0      │
├─────┼─────┼──────────┼──────────┼────────────┼────────────┤
│ 40  │ 16  │ 40-30=10 │ 16-12= 4 │  (10)(4)   │  (10)²     │
│     │     │          │          │    = 40    │   = 100    │
├─────┼─────┼──────────┼──────────┼────────────┼────────────┤
│ SUM │     │    0     │    0     │    80      │   200      │
└─────┴─────┴──────────┴──────────┴────────────┴────────────┘

Slope: 
m = (y₂ - y₁) / (x₂ - x₁)
m = (12 - 8) / (30 - 20)
m = 4 / 10
m = 0.4

OR
m = Sum of product of deviations / Sum of squares of deviations of X
m = 80 / 200 = 0.4


Y
│                          ·  ·
│                       ·
│                    · ·
│                 ·
│              ·  ·
│           ·
│        · ·
│      ·
│   ·  ·
│ ·
│·
└──────────────────────────────── X

         y = mx + b  (m > 0)


------------------------------------------------------------

Supervised -> Regession -> Logistic Regression
Dependent data is categroial and binary (0 and 1) .. Indenpendent is linear 

Indenpendent | Dependent
Study hours  | Exam Result 
2			 | 0
3			 | 0
4			 | 0
5			 | 1
6			 | 1
7			 | 1
8			 | 1

nearest probability 0.2 -> 0 and 0.8 -> 1

Sigmoid fucntion is used (values will be between 0,1)

y = 1 / 1 + e ^ - (a0 + a1 * x)

a0 (intercept) = 
a1 (coefficient) = how much does y change by changing x


 Y
 │                                    
1│                      · · · ·· · 
 │                    ·
 │                  ·
 │                 ·
 │                ·
 │               ·
 │              ·
 │            ·
 │           ·
0│· ·· · · ·
 │
 └──────────────────────────────── X

          y = 1 / (1 + e⁻ˣ)


i. Data Collection
┌──────────┬─────────────────┬──────────────────────┐
│ Order #  │ Distance (km)   │ On-Time Delivery     │
│          │      (X)        │   (Y: 0=No, 1=Yes)   │
├──────────┼─────────────────┼──────────────────────┤
│    1     │       2         │         1 (Yes)      │
│    2     │       3         │         1 (Yes)      │
│    3     │       5         │         1 (Yes)      │
│    4     │       7         │         0 (No)       │
│    5     │       8         │         0 (No)       │
│    6     │      10         │         0 (No)       │
└──────────┴─────────────────┴──────────────────────┘

ii. Logistic Regression Model

┌─────────────────────────────────────────┐
│                                         │
│  P(Y=1) =      1                        │
│           ─────────────                 │
│           1 + e^-(β₀ + β₁X)             │
│                                         │
│  Where:                                 │
│  • P(Y=1) = Probability of on-time      │
│  • e = 2.718 (Euler's number)           │
│  • β₀ = Intercept                       │
│  • β₁ = Coefficient                     │
│                                         │
└─────────────────────────────────────────┘


Fitted Model (example):
β₀ = 5.0  (intercept)
β₁ = -1.0 (coefficient for distance)

P(On-Time) =      1      
             ─────────────
             1 + e^-(5 - X)

iii. Calculation Table
┌──────────┬─────────┬──────────────┬──────────────┬────────────┐
│ Distance │  Z =    │   e^-Z       │  P(On-Time)  │  Actual    │
│   (km)   │ 5 - X   │              │  = 1/(1+e^-Z)│   Result   │
├──────────┼─────────┼──────────────┼──────────────┼────────────┤
│    2     │ 5-2= 3  │  e^-3=0.05   │ 1/(1+0.05)   │     1      │
│          │         │              │  = 0.95 ✓    │   (95%)    │
├──────────┼─────────┼──────────────┼──────────────┼────────────┤
│    3     │ 5-3= 2  │  e^-2=0.14   │ 1/(1+0.14)   │     1      │
│          │         │              │  = 0.88 ✓    │   (88%)    │
├──────────┼─────────┼──────────────┼──────────────┼────────────┤
│    5     │ 5-5= 0  │  e^0 =1.00   │ 1/(1+1.00)   │     1      │
│          │         │              │  = 0.50      │   (50%)    │
├──────────┼─────────┼──────────────┼──────────────┼────────────┤
│    7     │ 5-7=-2  │  e^2 =7.39   │ 1/(1+7.39)   │     0      │
│          │         │              │  = 0.12 ✓    │   (12%)    │
├──────────┼─────────┼──────────────┼──────────────┼────────────┤
│    8     │ 5-8=-3  │  e^3 =20.09  │ 1/(1+20.09)  │     0      │
│          │         │              │  = 0.05 ✓    │    (5%)    │
├──────────┼─────────┼──────────────┼──────────────┼────────────┤
│   10     │ 5-10=-5 │  e^5 =148.4  │ 1/(1+148.4)  │     0      │
│          │         │              │  = 0.007 ✓   │   (0.7%)   │
└──────────┴─────────┴──────────────┴──────────────┴────────────┘


------

Linear Regression
- Supervised regression model
- independent variable is continous
- dependent variable is continous
y = a0 + a1 * x


Logisitic Regression
- Supervised Classification model
- independent variable is continous
- dependent variable is desceret 
y = 1 / 1 + e ^ -(a0 + a1 * x)  -> Sigmoid func


------------------------------------------

kNN classification (predicting classes)
k-nearest neighbours algo (kNN)
Example: Predicting movie genre
 
Uses Eucilidean and Manhattan Distance formulae


Scenario: Predict if a customer will rate the pizza as "Good" or "Bad"

i. Training Data Collection
┌──────────┬─────────────┬─────────────┬──────────────┐
│Customer #│ Price ($)   │ Wait Time   │   Rating     │
│          │     (X₁)    │  (min) (X₂) │ (Good/Bad)   │
├──────────┼─────────────┼─────────────┼──────────────┤
│    A     │     8       │     15      │   Good ✓     │
│    B     │     10      │     20      │   Good ✓     │
│    C     │     12      │     25      │   Bad  ✗     │
│    D     │     15      │     30      │   Bad  ✗     │
│    E     │     9       │     18      │   Good ✓     │
│    F     │     14      │     35      │   Bad  ✗     │
│    G     │     7       │     12      │   Good ✓     │
└──────────┴─────────────┴─────────────┴──────────────┘

ii.New Customer to Predict
┌──────────────────────────────────────────┐
│  NEW CUSTOMER: ?                         │
│  • Price: $11                            │
│  • Wait Time: 22 minutes                 │
│  • Rating: ??? (to predict)              │
└──────────────────────────────────────────┘

iii. Calculate Distance (Euclidean)

Distance = √[(X₁new - X₁)² + (X₂new - X₂)²]

Distance Calculation Table:
┌──────────┬─────────┬───────────┬─────────────────────────┬──────────┬─────────┐
│Customer  │ Price   │ Wait Time │    Distance Calc        │ Distance │ Rating  │
├──────────┼─────────┼───────────┼─────────────────────────┼──────────┼─────────┤
│    A     │   8     │    15     │ √[(11-8)²+(22-15)²]     │   7.62   │  Good   │
│          │         │           │ √[9 + 49] = √58         │          │         │
├──────────┼─────────┼───────────┼─────────────────────────┼──────────┼─────────┤
│    B     │   10    │    20     │ √[(11-10)²+(22-20)²]    │   2.24   │  Good   │
│          │         │           │ √[1 + 4] = √5           │          │   ★     │
├──────────┼─────────┼───────────┼─────────────────────────┼──────────┼─────────┤
│    C     │   12    │    25     │ √[(11-12)²+(22-25)²]    │   3.16   │  Bad    │
│          │         │           │ √[1 + 9] = √10          │          │   ★     │
├──────────┼─────────┼───────────┼─────────────────────────┼──────────┼─────────┤
│    D     │   15    │    30     │ √[(11-15)²+(22-30)²]    │   8.94   │  Bad    │
│          │         │           │ √[16 + 64] = √80        │          │         │
├──────────┼─────────┼───────────┼─────────────────────────┼──────────┼─────────┤
│    E     │   9     │    18     │ √[(11-9)²+(22-18)²]     │   4.47   │  Good   │
│          │         │           │ √[4 + 16] = √20         │          │   ★     │
├──────────┼─────────┼───────────┼─────────────────────────┼──────────┼─────────┤
│    F     │   14    │    35     │ √[(11-14)²+(22-35)²]    │  13.34   │  Bad    │
│          │         │           │ √[9 + 169] = √178       │          │         │
├──────────┼─────────┼───────────┼─────────────────────────┼──────────┼─────────┤
│    G     │   7     │    12     │ √[(11-7)²+(22-12)²]     │  10.77   │  Good   │
│          │         │           │ √[16 + 100] = √116      │          │         │
└──────────┴─────────┴───────────┴─────────────────────────┴──────────┴─────────┘

★ = Nearest neighbors (for k=3)

iv. Sort by Distance
┌──────┬──────────┬──────────┬─────────┐
│ Rank │ Customer │ Distance │ Rating  │
├──────┼──────────┼──────────┼─────────┤
│  1   │    B     │   2.24   │  Good   │ ← Nearest
│  2   │    C     │   3.16   │  Bad    │ ← k=3
│  3   │    E     │   4.47   │  Good   │ ← Neighbors
├──────┼──────────┼──────────┼─────────┤
│  4   │    A     │   7.62   │  Good   │
│  5   │    D     │   8.94   │  Bad    │
│  6   │    G     │  10.77   │  Good   │
│  7   │    F     │  13.34   │  Bad    │
└──────┴──────────┴──────────┴─────────┘


Choosing the Right k

┌─────────┬───────────────────┬─────────────────────┐
│    k    │    Advantage      │    Disadvantage     │
├─────────┼───────────────────┼─────────────────────┤
│   k=1   │ Detailed, precise │ Sensitive to noise  │
│         │                   │ Overfitting risk    │
├─────────┼───────────────────┼─────────────────────┤
│   k=3   │ Balanced          │ Good compromise     │
│   k=5   │ More robust       │                     │
├─────────┼───────────────────┼─────────────────────┤
│  k=all  │ Simple majority   │ Underfitting        │
│         │                   │ Ignores locality    │
└─────────┴───────────────────┴─────────────────────┘

Rule of thumb: k = √n (where n = training samples)
For 7 samples: k ≈ √7 ≈ 3

------------------------------------------------------------
------------------------------------------------------------
------------------------------------------------------------


Naive Bayes Classification 
- based on bayes theorem

Naive Bayes Example - Pizza Order Prediction
Scenario: Will a customer order pizza today?

Step 1: Training Data Collection


┌──────────┬─────────────┬─────────────┬─────────────┬──────────────┐
│ Day      │  Weather    │  Weekend    │  Promotion  │ Ordered Pizza│
│          │             │  (Yes/No)   │  (Yes/No)   │  (Yes/No)    │
├──────────┼─────────────┼─────────────┼─────────────┼──────────────┤
│    1     │   Sunny     │     Yes     │     Yes     │    Yes ✓     │
│    2     │   Rainy     │     No      │     No      │    No  ✗     │
│    3     │   Sunny     │     Yes     │     No      │    Yes ✓     │
│    4     │   Cloudy    │     No      │     Yes     │    Yes ✓     │
│    5     │   Rainy     │     Yes     │     Yes     │    Yes ✓     │
│    6     │   Sunny     │     No      │     No      │    No  ✗     │
│    7     │   Cloudy    │     Yes     │     Yes     │    Yes ✓     │
│    8     │   Rainy     │     No      │     No      │    No  ✗     │
│    9     │   Sunny     │     Yes     │     Yes     │    Yes ✓     │
│   10     │   Cloudy    │     No      │     No      │    No  ✗     │
└──────────┴─────────────┴─────────────┴─────────────┴──────────────┘

Total: 10 days


Visual Representation:


                NAIVE BAYES DECISION TREE
                
                    Will Order? 
                        │
        ┌───────────────┼───────────────┐
        │                               │
    P(Yes) = 60%                   P(No) = 40%
        │                               │
    ┌───┴───┐                       ┌───┴───┐
    │       │                       │       │
  Sunny  Cloudy                   Sunny  Rainy
  (50%)  (33%)                    (50%)  (50%)
    │       │                       │       │
    └───┬───┘                       └───┬───┘
        │                               │
    Weekend?                        Weekend?
   Yes(83%)                         Yes(25%)
        │                               │
   Promotion?                      Promotion?
   Yes(83%)                        Yes(25%)
        │                               │
        ▼                               ▼
    ORDER! 🍕                       NO ORDER



------------------------------------------------------------------------------------------------------------------------------------------------------

Decision Tree
used for both classification and regression
- Tree Structure
- Decision Nodes
- Leaf nodes (Outcomes)
- Spliting
- Entropy and Information gain
- Pruning (removing unnecessary ndoes)

ID3 algo/Random forest

ID3 algo
The ID3 (Iterative Dichotomiser 3) algorithm is a foundational machine learning method used to construct a [decision tree](https://www.geeksfor Geeks.org/machine-learning/sklearn-iterative-dichotomiser-3-id3-algorithms/) from a given dataset, primarily for classification tasks. It employs a top-down, greedy approach, meaning it makes the best local choice at each step without considering future outcomes. 


-> Entropy and information gain

┌────┬─────────┬──────────┬───────────┬──────────────┐
│ #  │ Weather │ Weekend  │ Promotion │ Order Pizza? │
├────┼─────────┼──────────┼───────────┼──────────────┤
│ 1  │ Sunny   │   Yes    │    Yes    │    Yes ✓     │
│ 2  │ Rainy   │   No     │    No     │    No  ✗     │
│ 3  │ Sunny   │   Yes    │    No     │    Yes ✓     │
│ 4  │ Cloudy  │   No     │    Yes    │    Yes ✓     │
│ 5  │ Rainy   │   Yes    │    Yes    │    Yes ✓     │
│ 6  │ Sunny   │   No     │    No     │    No  ✗     │
│ 7  │ Cloudy  │   Yes    │    Yes    │    Yes ✓     │
│ 8  │ Rainy   │   No     │    No     │    No  ✗     │
│ 9  │ Sunny   │   Yes    │    Yes    │    Yes ✓     │
│ 10 │ Cloudy  │   No     │    No     │    No  ✗     │
└────┴─────────┴──────────┴───────────┴──────────────┘

Total: 10 samples
Yes: 6 samples
No:  4 samples

Calculate Entropy of Root (Before Split)
Entropy(S) = -Σ pᵢ × log₂(pᵢ)

------------------------------------------------

Conditional Probability 

