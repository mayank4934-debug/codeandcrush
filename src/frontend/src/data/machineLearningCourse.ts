import type {
  CModule,
  CQuizQuestion,
  CTestProblem,
} from "./cProgrammingCourse";

// ─── Module 0: Orientation ────────────────────────────────────────────────────

const ml_module0: CModule = {
  id: "machine-learning-module0",
  title: "Module 0: Getting Started",
  outcome:
    "Understand the course structure, learning path, how modules unlock, how quizzes work, and what XP you earn",
  isLocked: false,
  estimatedHours: 45,
  quizAfterModule: false,
  parts: [
    {
      id: "machine-learning-module0-orientation",
      title: "Course Orientation",
      description:
        "Welcome to Machine Learning! Your companion will guide you through everything you need to know before you start.",
      videoUrl: "",
      hasCodingContent: false,
      notes: `WELCOME TO MACHINE LEARNING!

Hey! I'm beyond excited to be your companion on this Machine Learning journey! 🤖 ML is one of the most transformative technologies of our time — powering recommendation systems, self-driving cars, medical diagnostics, and so much more. Let's explore it together!

COURSE OVERVIEW
Machine Learning is a branch of AI where systems learn patterns from data without being explicitly programmed. You'll study the mathematical foundations (linear algebra, calculus, statistics), Python for ML (NumPy, Pandas, scikit-learn), classical algorithms (regression, decision trees, SVM, clustering), and neural networks and deep learning. This course prepares you for ML engineering roles and research.

HOW THIS COURSE WORKS
This course has 5 modules, each unlocking after you complete the previous one. Each module has several Parts. Every Part contains: a Video (watch to learn), a Lesson (read for deeper understanding), a Documentation link (open in-app for reference), a Quiz (15 MCQs to test your knowledge), and Coding Questions (in parts where you implement ML algorithms). After all parts, there's a Module Test. Complete the test to unlock the next module!

HOW YOU EARN
• 5 XP per correct MCQ answer in quizzes
• 20 XP per completed coding question
• Badges for completing each module
• SP (Study Points) for in-app purchases
• GCoins for daily challenges and streaks

ESTIMATED COMPLETION TIME: ~45 hours
This is a deep, rigorous course. Dedicate 1–2 hours per day and you'll be building real ML models in about 5–6 weeks.

WHAT TO DO NEXT
Complete the Getting Started checklist below, then scroll down to Module 1 to begin! 🚀`,
      docs: [],
      partQuiz: [],
      partProgrammingQuestions: [],
      subsections: [
        {
          id: "machine-learning-module0-learning-path",
          title: "Your Learning Path",
          content: `Here's the complete roadmap for this Machine Learning course:

1. Math Foundations — Linear algebra, calculus, probability, statistics for ML
2. Python for ML — NumPy, Pandas, Matplotlib, scikit-learn setup
3. Classical ML Algorithms — Linear regression, logistic regression, decision trees, SVM, clustering
4. Neural Networks — Perceptrons, backpropagation, activation functions
5. Deep Learning — CNNs, RNNs, TensorFlow/Keras for training models
6. Projects — Real-world ML projects: image classification, NLP, tabular prediction`,
          codeExample: "",
        },
        {
          id: "machine-learning-module0-module-structure",
          title: "How Modules Work",
          content: `Each module in this course is broken into Parts. Here's how a typical Part is structured:

• Video — A curated video explaining the concept visually
• Lesson — In-depth readable content you can study at your own pace
• Documentation — In-app reference material for that topic
• Quiz — 15 multiple-choice questions (5 XP each) to reinforce learning
• Coding Questions — Hands-on exercises in parts where you implement ML algorithms

Math-heavy theory parts may not have coding questions. Only parts where you write actual Python ML code include programming exercises.

Module Unlock Rules:
• Module 1 is always unlocked and ready to start
• Each subsequent module unlocks after you pass the previous module's test
• You can retake quizzes to improve your score`,
          codeExample: "",
        },
        {
          id: "machine-learning-module0-checklist",
          title: "Getting Started Checklist",
          content: `Complete these steps before heading to Module 1:

1. Read the course overview above — understand what machine learning is and why it matters
2. Meet your study companion — they'll guide you through every lesson with hints and encouragement
3. Understand how modules unlock — complete one module's test to access the next
4. Know how quizzes work — 15 MCQs per part, plus coding questions in coding topics
5. Check your XP progress bar in the sidebar — it grows as you complete lessons and quizzes
6. You're all set! Head to Module 1 below to begin your Machine Learning journey 🎉`,
          codeExample: "",
        },
      ],
    },
  ],
  moduleQuiz: [],
  moduleTest: [],
};

// ─── Module 1: ML Foundations ─────────────────────────────────────────────────

const ml_module1: CModule = {
  id: "ml-foundations",
  title: "Module 1: ML Foundations",
  outcome: "Understand ML types, core math, and Python libraries for ML.",
  isLocked: false,
  quizAfterModule: true,
  parts: [
    {
      id: "ml-m1-p1",
      title: "Part 1: ML Types",
      description: "Supervised, unsupervised, and reinforcement learning.",
      hasCodingContent: true,
      videoUrl: "https://www.youtube.com/watch?v=ukzFI9rgwfU",
      notes:
        "Machine learning is categorized into supervised (labeled data), unsupervised (unlabeled), and reinforcement learning (reward-based).",
      docs: [],
      partQuiz: [
        {
          question: "Which ML type uses labeled training data?",
          options: [
            "Unsupervised",
            "Supervised",
            "Reinforcement",
            "Semi-supervised",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "Which algorithm groups similar data without labels?",
          options: ["Linear Regression", "Decision Tree", "K-Means", "SVM"],
          correct: 2,
          xp: 10,
        },
        {
          question: "What is overfitting?",
          options: [
            "Model too simple",
            "Model memorizes training data",
            "Underfitting",
            "Data leakage",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What is the purpose of a test set?",
          options: [
            "Train the model",
            "Tune hyperparameters",
            "Evaluate generalization",
            "Augment data",
          ],
          correct: 2,
          xp: 10,
        },
        {
          question: "Which learning type trains via rewards?",
          options: ["Supervised", "Unsupervised", "Reinforcement", "Transfer"],
          correct: 2,
          xp: 10,
        },
      ] as CQuizQuestion[],
      subsections: [
        {
          id: "ml-m1-p1s1",
          title: "Supervised Learning",
          content:
            "Supervised learning maps inputs to outputs using labeled examples. Classification predicts categories; regression predicts continuous values.",
          codeExample:
            "# Supervised: predict house price from features\nfrom sklearn.linear_model import LinearRegression\nX = [[1000], [1500], [2000]]\ny = [200000, 300000, 400000]\nmodel = LinearRegression().fit(X, y)\nprint(model.predict([[1750]]))",
          hasDocumentation: true,
          video: { youtubeId: "ukzFI9rgwfU", title: "Supervised Learning" },
          flowchart: "compilation-pipeline",
        },
        {
          id: "ml-m1-p1s2",
          title: "Unsupervised Learning",
          content:
            "Unsupervised learning finds structure in unlabeled data. Clustering groups similar points; dimensionality reduction compresses features.",
          codeExample:
            "from sklearn.cluster import KMeans\nimport numpy as np\nX = np.array([[1,2],[1,4],[3,2],[8,7],[9,8]])\nkmeans = KMeans(n_clusters=2, random_state=0).fit(X)\nprint(kmeans.labels_)",
          hasDocumentation: true,
          video: { youtubeId: "ukzFI9rgwfU", title: "Unsupervised Learning" },
          flowchart: "if-else",
        },
        {
          id: "ml-m1-p1s3",
          title: "Train/Test Split & Overfitting",
          content:
            "Split data into training (80%) and test (20%) sets. Overfitting: high train accuracy, low test accuracy. Use cross-validation to detect it.",
          codeExample:
            "from sklearn.model_selection import train_test_split\nX = [[i] for i in range(100)]\ny = [i*2 for i in range(100)]\nX_train, X_test, y_train, y_test = train_test_split(X, y, test_size=0.2, random_state=42)\nprint(len(X_train), len(X_test))",
          hasDocumentation: true,
          video: { youtubeId: "ukzFI9rgwfU", title: "Train/Test Split" },
          flowchart: "loop",
        },
      ],
    },
    {
      id: "ml-m1-p2",
      title: "Part 2: Math Basics",
      description: "Linear algebra, calculus, and probability for ML.",
      videoUrl: "https://www.youtube.com/watch?v=mSMDP_pdjL4",
      hasCodingContent: true,
      notes:
        "ML relies on vectors/matrices (linear algebra), gradients (calculus), and probability for uncertainty modeling.",
      docs: [],
      partQuiz: [
        {
          question: "What is a dot product used for in ML?",
          options: [
            "Sorting data",
            "Measuring similarity",
            "Counting rows",
            "Splitting data",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What does a gradient represent?",
          options: [
            "Loss value",
            "Direction of steepest ascent",
            "Learning rate",
            "Matrix rank",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What is gradient descent?",
          options: [
            "Finding max loss",
            "Iteratively minimizing loss",
            "Computing gradients",
            "Batch processing",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What is a matrix transpose?",
          options: [
            "Inverse matrix",
            "Rows become columns",
            "Diagonal extraction",
            "Scalar product",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "Which function maps values to 0-1 range?",
          options: ["ReLU", "Sigmoid", "Tanh", "Softmax"],
          correct: 1,
          xp: 10,
        },
      ] as CQuizQuestion[],
      subsections: [
        {
          id: "ml-m1-p2s1",
          title: "Vectors & Matrices",
          content:
            "Vectors represent data points; matrices represent datasets or transformations. Matrix multiplication is the foundation of neural networks.",
          codeExample:
            "import numpy as np\nv = np.array([1, 2, 3])\nM = np.array([[1,2],[3,4],[5,6]])\nprint('Dot:', np.dot(v[:2], v[1:3]))\nprint('Transpose:\\n', M.T)\nprint('MatMul:\\n', M.T @ M)",
          hasDocumentation: true,
          video: { youtubeId: "mSMDP_pdjL4", title: "Vectors & Matrices" },
          flowchart: "compilation-pipeline",
        },
        {
          id: "ml-m1-p2s2",
          title: "Gradients & Optimization",
          content:
            "Gradient descent updates model weights by moving in the direction opposite to the gradient of the loss function.",
          codeExample:
            "# Manual gradient descent for y = x^2\nx = 10.0\nlr = 0.1\nfor i in range(20):\n    grad = 2 * x  # derivative of x^2\n    x -= lr * grad\n    if i % 5 == 0:\n        print(f'Step {i}: x={x:.4f}, loss={x**2:.4f}')",
          hasDocumentation: true,
          video: { youtubeId: "mSMDP_pdjL4", title: "Gradient Descent" },
          flowchart: "loop",
        },
        {
          id: "ml-m1-p2s3",
          title: "Activation Functions",
          content:
            "Activation functions add non-linearity. Sigmoid: 0-1 for binary output. ReLU: max(0,x) for hidden layers. Softmax: probability distribution for multi-class.",
          codeExample:
            "import numpy as np\ndef sigmoid(x): return 1 / (1 + np.exp(-x))\ndef relu(x): return np.maximum(0, x)\ndef softmax(x): return np.exp(x) / np.sum(np.exp(x))\nx = np.array([-2, -1, 0, 1, 2])\nprint('Sigmoid:', sigmoid(x).round(3))\nprint('ReLU:   ', relu(x))\nprint('Softmax:', softmax(x).round(3))",
          hasDocumentation: true,
          video: { youtubeId: "mSMDP_pdjL4", title: "Activation Functions" },
          flowchart: "if-else",
        },
      ],
    },
    {
      id: "ml-m1-p3",
      title: "Part 3: Python Libraries",
      description: "Scikit-learn, NumPy, Pandas for ML pipelines.",
      videoUrl: "https://www.youtube.com/watch?v=0Lt9w-BxKFQ",
      hasCodingContent: true,
      notes:
        "Scikit-learn provides a consistent API for ML models; NumPy handles math; Pandas manages data.",
      docs: [],
      partQuiz: [
        {
          question: "What does fit() do in scikit-learn?",
          options: [
            "Predicts output",
            "Trains the model",
            "Evaluates accuracy",
            "Splits data",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "Which scikit-learn function standardizes features?",
          options: [
            "Normalizer",
            "StandardScaler",
            "MinMaxScaler",
            "Binarizer",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What does Pipeline in sklearn do?",
          options: [
            "Runs in parallel",
            "Chains preprocessing and model steps",
            "Plots results",
            "Evaluates metrics",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "How do you evaluate classification accuracy?",
          options: [
            "r2_score",
            "mean_squared_error",
            "accuracy_score",
            "log_loss",
          ],
          correct: 2,
          xp: 10,
        },
        {
          question: "What does cross_val_score return?",
          options: [
            "Single accuracy",
            "Array of scores per fold",
            "Confusion matrix",
            "Feature importances",
          ],
          correct: 1,
          xp: 10,
        },
      ] as CQuizQuestion[],
      subsections: [
        {
          id: "ml-m1-p3s1",
          title: "Scikit-learn Basics",
          content:
            "Every sklearn estimator follows: fit(X, y) → predict(X) → score(X, y). This consistent API makes switching models trivial.",
          codeExample:
            "from sklearn.neighbors import KNeighborsClassifier\nfrom sklearn.datasets import load_iris\nfrom sklearn.model_selection import train_test_split\nX, y = load_iris(return_X_y=True)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2)\nknn = KNeighborsClassifier(n_neighbors=3)\nknn.fit(X_tr, y_tr)\nprint('Accuracy:', knn.score(X_te, y_te))",
          hasDocumentation: true,
          video: { youtubeId: "0Lt9w-BxKFQ", title: "Scikit-learn Basics" },
          flowchart: "compilation-pipeline",
        },
        {
          id: "ml-m1-p3s2",
          title: "Feature Scaling",
          content:
            "StandardScaler: zero mean, unit variance. MinMaxScaler: scales to [0,1]. Always fit on training data only, then transform both train and test.",
          codeExample:
            "from sklearn.preprocessing import StandardScaler\nimport numpy as np\nX_train = np.array([[1,100],[2,200],[3,300]])\nX_test = np.array([[4,400]])\nscaler = StandardScaler()\nX_train_s = scaler.fit_transform(X_train)\nX_test_s = scaler.transform(X_test)\nprint('Scaled train:\\n', X_train_s)",
          hasDocumentation: true,
          video: { youtubeId: "0Lt9w-BxKFQ", title: "Feature Scaling" },
          flowchart: "if-else",
        },
        {
          id: "ml-m1-p3s3",
          title: "Pipelines & Cross-Validation",
          content:
            "Pipeline chains scaler + model. cross_val_score runs k-fold CV to get robust performance estimates without data leakage.",
          codeExample:
            "from sklearn.pipeline import Pipeline\nfrom sklearn.preprocessing import StandardScaler\nfrom sklearn.svm import SVC\nfrom sklearn.model_selection import cross_val_score\nfrom sklearn.datasets import load_iris\nX, y = load_iris(return_X_y=True)\npipe = Pipeline([('scaler', StandardScaler()), ('svm', SVC())])\nscores = cross_val_score(pipe, X, y, cv=5)\nprint('CV scores:', scores.round(3))\nprint('Mean:', scores.mean().round(3))",
          hasDocumentation: true,
          video: { youtubeId: "0Lt9w-BxKFQ", title: "Pipelines" },
          flowchart: "loop",
        },
      ],
    },
  ],
  moduleQuiz: [
    {
      question: "Which ML type requires labeled data?",
      options: [
        "Unsupervised",
        "Supervised",
        "Reinforcement",
        "Self-supervised",
      ],
      correct: 1,
      xp: 10,
    },
    {
      question: "What does StandardScaler do?",
      options: [
        "Normalizes to [0,1]",
        "Zero mean, unit variance",
        "Removes outliers",
        "Encodes categories",
      ],
      correct: 1,
      xp: 10,
    },
    {
      question: "What is overfitting?",
      options: [
        "Low bias, high variance",
        "Model too simple",
        "High bias, low variance",
        "Low training error",
      ],
      correct: 0,
      xp: 10,
    },
    {
      question: "What is gradient descent used for?",
      options: [
        "Data cleaning",
        "Minimizing loss function",
        "Feature selection",
        "Cross-validation",
      ],
      correct: 1,
      xp: 10,
    },
    {
      question: "What does cross_val_score measure?",
      options: [
        "Training accuracy",
        "Generalization via k-fold CV",
        "Loss function",
        "Feature importance",
      ],
      correct: 1,
      xp: 10,
    },
  ] as CQuizQuestion[],
  moduleTest: [
    {
      id: "ml-m1-test1",
      title: "Build a Classifier with Sklearn Pipeline",
      description:
        "Create a Pipeline with StandardScaler and KNeighborsClassifier. Train on Iris data, run 5-fold cross-validation, and print the mean accuracy.",
      starterCode:
        "from sklearn.pipeline import Pipeline\nfrom sklearn.preprocessing import StandardScaler\nfrom sklearn.neighbors import KNeighborsClassifier\nfrom sklearn.model_selection import cross_val_score\nfrom sklearn.datasets import load_iris\n\nX, y = load_iris(return_X_y=True)\n\n# Build pipeline and run 5-fold CV\n# Print mean accuracy\n",
      hints: [
        "Use Pipeline([('scaler', StandardScaler()), ('knn', KNeighborsClassifier())])",
        "Use cross_val_score(pipe, X, y, cv=5)",
        "Print scores.mean()",
      ],
    },
  ] as CTestProblem[],
};

// ─── Module 2: Supervised Learning ────────────────────────────────────────────

const ml_module2: CModule = {
  id: "ml-supervised",
  title: "Module 2: Supervised Learning",
  outcome: "Implement linear regression, decision trees, and SVMs.",
  isLocked: true,
  quizAfterModule: true,
  parts: [
    {
      id: "ml-m2-p1",
      title: "Part 1: Linear Regression",
      description: "Fit lines to data, evaluate with MSE and R².",
      videoUrl: "https://www.youtube.com/watch?v=nk2CQITm_eo",
      hasCodingContent: true,
      notes:
        "Linear regression models the relationship between features and a continuous target by fitting a straight line.",
      docs: [],
      partQuiz: [
        {
          question: "What does linear regression predict?",
          options: [
            "Categories",
            "Continuous values",
            "Clusters",
            "Probabilities",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What metric measures average squared prediction error?",
          options: ["R²", "MAE", "MSE", "Accuracy"],
          correct: 2,
          xp: 10,
        },
        {
          question: "What does R² = 1 mean?",
          options: ["Perfect fit", "No fit", "Overfit", "50% explained"],
          correct: 0,
          xp: 10,
        },
        {
          question: "What is regularization used for?",
          options: [
            "Speed up training",
            "Reduce overfitting",
            "Increase bias",
            "Scale features",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "Which regression adds L1 penalty?",
          options: ["Ridge", "Lasso", "ElasticNet", "Linear"],
          correct: 1,
          xp: 10,
        },
      ] as CQuizQuestion[],
      subsections: [
        {
          id: "ml-m2-p1s1",
          title: "Simple Linear Regression",
          content:
            "Linear regression finds coefficients w such that y ≈ w·X + b minimizing mean squared error.",
          codeExample:
            "from sklearn.linear_model import LinearRegression\nfrom sklearn.metrics import mean_squared_error, r2_score\nimport numpy as np\nX = np.array([[1],[2],[3],[4],[5]])\ny = [2.1, 3.9, 6.2, 7.8, 10.1]\nmodel = LinearRegression().fit(X, y)\npred = model.predict(X)\nprint('MSE:', mean_squared_error(y, pred).round(3))\nprint('R2: ', r2_score(y, pred).round(3))",
          video: { youtubeId: "nk2CQITm_eo", title: "Linear Regression" },
          flowchart: "compilation-pipeline",
        },
        {
          id: "ml-m2-p1s2",
          title: "Multiple Features",
          content:
            "Multiple linear regression uses several features. Feature scaling improves convergence. Check multicollinearity with correlation matrix.",
          codeExample:
            "from sklearn.datasets import load_diabetes\nfrom sklearn.linear_model import LinearRegression\nfrom sklearn.model_selection import train_test_split\nX, y = load_diabetes(return_X_y=True)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2)\nmodel = LinearRegression().fit(X_tr, y_tr)\nprint('Test R2:', model.score(X_te, y_te).round(3))",
          video: { youtubeId: "nk2CQITm_eo", title: "Multiple Regression" },
          flowchart: "if-else",
        },
        {
          id: "ml-m2-p1s3",
          title: "Ridge & Lasso Regularization",
          content:
            "Ridge (L2) shrinks all weights. Lasso (L1) can zero out weights for feature selection. Use alpha to control regularization strength.",
          codeExample:
            "from sklearn.linear_model import Ridge, Lasso\nfrom sklearn.datasets import load_diabetes\nfrom sklearn.model_selection import train_test_split\nX, y = load_diabetes(return_X_y=True)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2)\nfor Model, name in [(Ridge, 'Ridge'), (Lasso, 'Lasso')]:\n    m = Model(alpha=1.0).fit(X_tr, y_tr)\n    print(f'{name} R2: {m.score(X_te, y_te):.3f}')",
          video: { youtubeId: "nk2CQITm_eo", title: "Regularization" },
          flowchart: "loop",
        },
      ],
    },
    {
      id: "ml-m2-p2",
      title: "Part 2: Decision Trees",
      description: "Tree-based classification and regression.",
      videoUrl: "https://www.youtube.com/watch?v=RmajweUFKvM",
      hasCodingContent: true,
      notes:
        "Decision trees split data on feature thresholds to minimize impurity; they're interpretable but prone to overfitting.",
      docs: [],
      partQuiz: [
        {
          question: "What metric does Decision Tree use to split?",
          options: ["MSE only", "Gini or Entropy", "R²", "Accuracy"],
          correct: 1,
          xp: 10,
        },
        {
          question: "How do you prevent Decision Tree overfitting?",
          options: [
            "Increase depth",
            "Limit max_depth",
            "Remove features",
            "Add more data only",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What is a Random Forest?",
          options: [
            "Single deep tree",
            "Ensemble of decision trees",
            "Gradient boosted trees",
            "Neural network",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What does feature_importances_ return?",
          options: [
            "Correlation values",
            "Relative importance of each feature",
            "P-values",
            "Weights",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What is bagging in Random Forest?",
          options: [
            "Pruning trees",
            "Training trees on random data subsets",
            "Boosting residuals",
            "Dropout",
          ],
          correct: 1,
          xp: 10,
        },
      ] as CQuizQuestion[],
      subsections: [
        {
          id: "ml-m2-p2s1",
          title: "Decision Tree Classifier",
          content:
            "Decision trees recursively split on the feature+threshold that maximizes information gain (entropy) or minimizes Gini impurity.",
          codeExample:
            "from sklearn.tree import DecisionTreeClassifier\nfrom sklearn.datasets import load_iris\nfrom sklearn.model_selection import train_test_split\nX, y = load_iris(return_X_y=True)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2)\ntree = DecisionTreeClassifier(max_depth=3, random_state=42)\ntree.fit(X_tr, y_tr)\nprint('Accuracy:', tree.score(X_te, y_te))",
          video: { youtubeId: "RmajweUFKvM", title: "Decision Trees" },
          flowchart: "if-else",
        },
        {
          id: "ml-m2-p2s2",
          title: "Random Forest",
          content:
            "Random Forest builds many trees on random data subsets and averages predictions, reducing variance (overfitting) significantly.",
          codeExample:
            "from sklearn.ensemble import RandomForestClassifier\nfrom sklearn.datasets import load_iris\nfrom sklearn.model_selection import train_test_split\nX, y = load_iris(return_X_y=True)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2)\nrf = RandomForestClassifier(n_estimators=100, random_state=42)\nrf.fit(X_tr, y_tr)\nprint('Accuracy:', rf.score(X_te, y_te))\nprint('Feature importances:', rf.feature_importances_.round(3))",
          video: { youtubeId: "RmajweUFKvM", title: "Random Forest" },
          flowchart: "compilation-pipeline",
        },
        {
          id: "ml-m2-p2s3",
          title: "Hyperparameter Tuning",
          content:
            "GridSearchCV exhaustively tries hyperparameter combinations with cross-validation to find the best settings.",
          codeExample:
            "from sklearn.model_selection import GridSearchCV\nfrom sklearn.ensemble import RandomForestClassifier\nfrom sklearn.datasets import load_iris\nX, y = load_iris(return_X_y=True)\nparam_grid = {'n_estimators': [50, 100], 'max_depth': [3, 5, None]}\ngrid = GridSearchCV(RandomForestClassifier(), param_grid, cv=5)\ngrid.fit(X, y)\nprint('Best params:', grid.best_params_)\nprint('Best score: ', grid.best_score_.round(3))",
          video: { youtubeId: "RmajweUFKvM", title: "Grid Search" },
          flowchart: "loop",
        },
      ],
    },
    {
      id: "ml-m2-p3",
      title: "Part 3: SVMs",
      description: "Support Vector Machines for classification.",
      videoUrl: "https://www.youtube.com/watch?v=efR1C6CvhmE",
      hasCodingContent: true,
      notes:
        "SVMs find the maximum-margin hyperplane separating classes; kernel trick handles non-linear boundaries.",
      docs: [],
      partQuiz: [
        {
          question: "What does SVM maximize?",
          options: [
            "Accuracy",
            "Margin between classes",
            "Number of support vectors",
            "Feature count",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What are support vectors?",
          options: [
            "All training points",
            "Points closest to the decision boundary",
            "Outliers",
            "Test samples",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "Which kernel handles non-linear data?",
          options: ["Linear", "RBF", "Constant", "Identity"],
          correct: 1,
          xp: 10,
        },
        {
          question: "What does C parameter control?",
          options: [
            "Kernel type",
            "Margin vs misclassification tradeoff",
            "Learning rate",
            "Feature count",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "When is SVM slower?",
          options: [
            "Small datasets",
            "Large datasets with many samples",
            "Binary classification",
            "Normalized data",
          ],
          correct: 1,
          xp: 10,
        },
      ] as CQuizQuestion[],
      subsections: [
        {
          id: "ml-m2-p3s1",
          title: "SVM Classifier",
          content:
            "SVC with linear kernel works for linearly separable data. The C parameter trades off margin width vs classification errors.",
          codeExample:
            "from sklearn.svm import SVC\nfrom sklearn.datasets import load_iris\nfrom sklearn.preprocessing import StandardScaler\nfrom sklearn.pipeline import Pipeline\nfrom sklearn.model_selection import train_test_split\nX, y = load_iris(return_X_y=True)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2)\npipe = Pipeline([('scaler', StandardScaler()), ('svm', SVC(kernel='linear'))])\npipe.fit(X_tr, y_tr)\nprint('Accuracy:', pipe.score(X_te, y_te))",
          video: { youtubeId: "efR1C6CvhmE", title: "SVM Classifier" },
          flowchart: "if-else",
        },
        {
          id: "ml-m2-p3s2",
          title: "Kernel Trick",
          content:
            "The RBF kernel maps data to higher dimensions implicitly, enabling non-linear classification without computing the transformation explicitly.",
          codeExample:
            "from sklearn.svm import SVC\nfrom sklearn.datasets import make_moons\nfrom sklearn.model_selection import train_test_split\nX, y = make_moons(n_samples=200, noise=0.15, random_state=42)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2)\nfor kernel in ['linear', 'rbf', 'poly']:\n    svm = SVC(kernel=kernel).fit(X_tr, y_tr)\n    print(f'{kernel}: {svm.score(X_te, y_te):.3f}')",
          video: { youtubeId: "efR1C6CvhmE", title: "Kernel Trick" },
          flowchart: "compilation-pipeline",
        },
        {
          id: "ml-m2-p3s3",
          title: "Classification Metrics",
          content:
            "Beyond accuracy: precision (correct positives), recall (found positives), F1 (harmonic mean). Use confusion matrix to analyze errors.",
          codeExample:
            "from sklearn.metrics import classification_report, confusion_matrix\nfrom sklearn.svm import SVC\nfrom sklearn.datasets import load_iris\nfrom sklearn.model_selection import train_test_split\nX, y = load_iris(return_X_y=True)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2)\nsvm = SVC().fit(X_tr, y_tr)\npred = svm.predict(X_te)\nprint(classification_report(y_te, pred))\nprint('Confusion matrix:\\n', confusion_matrix(y_te, pred))",
          video: { youtubeId: "efR1C6CvhmE", title: "Classification Metrics" },
          flowchart: "loop",
        },
      ],
    },
  ],
  moduleQuiz: [
    {
      question: "What does R² = 0 mean for linear regression?",
      options: ["Perfect fit", "Predicts mean only", "Negative fit", "Overfit"],
      correct: 1,
      xp: 10,
    },
    {
      question: "Which ensemble method uses bootstrap sampling?",
      options: ["Boosting", "Stacking", "Bagging / Random Forest", "Voting"],
      correct: 2,
      xp: 10,
    },
    {
      question: "Which kernel is best for non-linear SVM?",
      options: ["Linear", "RBF", "Constant", "Sigmoid always"],
      correct: 1,
      xp: 10,
    },
    {
      question: "What does Lasso regularization do differently than Ridge?",
      options: [
        "Larger penalty",
        "Can zero out features",
        "Faster training",
        "Uses L2 norm",
      ],
      correct: 1,
      xp: 10,
    },
    {
      question: "What does precision measure?",
      options: [
        "All positives found",
        "Correct positive predictions ratio",
        "F1 score",
        "Recall",
      ],
      correct: 1,
      xp: 10,
    },
  ] as CQuizQuestion[],
  moduleTest: [
    {
      id: "ml-m2-test1",
      title: "Compare Classifiers",
      description:
        "Train a Decision Tree, Random Forest, and SVM on the Iris dataset. Print each model's test accuracy.",
      starterCode:
        "from sklearn.tree import DecisionTreeClassifier\nfrom sklearn.ensemble import RandomForestClassifier\nfrom sklearn.svm import SVC\nfrom sklearn.datasets import load_iris\nfrom sklearn.model_selection import train_test_split\n\nX, y = load_iris(return_X_y=True)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2, random_state=42)\n\n# Train each model and print accuracy\n",
      hints: [
        "Create each model with default params and call .fit(X_tr, y_tr)",
        "Use .score(X_te, y_te) to get accuracy",
        "Print model name + accuracy in a loop or individually",
      ],
    },
  ] as CTestProblem[],
};

// ─── Module 3: Advanced Algorithms ────────────────────────────────────────────

const ml_module3: CModule = {
  id: "ml-advanced-algorithms",
  title: "Module 3: Advanced Algorithms",
  outcome:
    "Master SVM, ensemble methods, clustering, and dimensionality reduction.",
  isLocked: true,
  quizAfterModule: true,
  parts: [
    {
      id: "ml-m3-p1",
      title: "Part 1: Support Vector Machines",
      description: "Margin maximization, kernels, and multi-class SVM.",
      videoUrl: "https://www.youtube.com/watch?v=efR1C6CvhmE",
      hasCodingContent: true,
      notes:
        "SVMs find the maximum-margin hyperplane separating classes; the kernel trick handles non-linear boundaries without explicit feature transformation.",
      docs: [],
      partQuiz: [
        {
          question: "What does SVM maximize?",
          options: [
            "Accuracy",
            "Margin between classes",
            "Number of support vectors",
            "Feature count",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What are support vectors?",
          options: [
            "All training points",
            "Points closest to the decision boundary",
            "Outliers",
            "Test samples",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "Which kernel handles non-linear data?",
          options: ["Linear", "RBF", "Constant", "Identity"],
          correct: 1,
          xp: 10,
        },
        {
          question: "What does the C parameter control in SVM?",
          options: [
            "Kernel type",
            "Margin vs misclassification tradeoff",
            "Learning rate",
            "Feature count",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "Which metric is best for imbalanced classification?",
          options: ["Accuracy", "F1-score", "MSE", "R²"],
          correct: 1,
          xp: 10,
        },
      ] as CQuizQuestion[],
      subsections: [
        {
          id: "ml-m3-p1s1",
          title: "SVM Classifier",
          content:
            "SVC with linear kernel works for linearly separable data. The C parameter trades margin width vs classification errors. Always scale features before SVM.",
          codeExample:
            "from sklearn.svm import SVC\nfrom sklearn.datasets import load_iris\nfrom sklearn.preprocessing import StandardScaler\nfrom sklearn.pipeline import Pipeline\nfrom sklearn.model_selection import train_test_split\nX, y = load_iris(return_X_y=True)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2)\npipe = Pipeline([('scaler', StandardScaler()), ('svm', SVC(kernel='linear', C=1.0))])\npipe.fit(X_tr, y_tr)\nprint('Accuracy:', pipe.score(X_te, y_te))",
          video: { youtubeId: "efR1C6CvhmE", title: "SVM Classifier" },
          flowchart: "if-else",
        },
        {
          id: "ml-m3-p1s2",
          title: "Kernel Trick & RBF",
          content:
            "The RBF kernel maps data to higher dimensions implicitly, enabling non-linear classification. The gamma parameter controls decision boundary curvature.",
          codeExample:
            "from sklearn.svm import SVC\nfrom sklearn.datasets import make_moons\nfrom sklearn.model_selection import train_test_split\nX, y = make_moons(n_samples=200, noise=0.15, random_state=42)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2)\nfor kernel in ['linear', 'rbf', 'poly']:\n    svm = SVC(kernel=kernel).fit(X_tr, y_tr)\n    print(f'{kernel}: {svm.score(X_te, y_te):.3f}')",
          video: { youtubeId: "efR1C6CvhmE", title: "Kernel Trick" },
          flowchart: "compilation-pipeline",
        },
        {
          id: "ml-m3-p1s3",
          title: "Classification Metrics",
          content:
            "Precision (correct positives), recall (found positives), F1 (harmonic mean). Use confusion matrix to analyze per-class errors.",
          codeExample:
            "from sklearn.metrics import classification_report, confusion_matrix\nfrom sklearn.svm import SVC\nfrom sklearn.datasets import load_iris\nfrom sklearn.model_selection import train_test_split\nX, y = load_iris(return_X_y=True)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2)\nsvm = SVC().fit(X_tr, y_tr)\npred = svm.predict(X_te)\nprint(classification_report(y_te, pred))\nprint('Confusion matrix:\\n', confusion_matrix(y_te, pred))",
          video: { youtubeId: "efR1C6CvhmE", title: "Classification Metrics" },
          flowchart: "loop",
        },
      ],
    },
    {
      id: "ml-m3-p2",
      title: "Part 2: Random Forest & Ensemble Methods",
      description: "Bagging, boosting, and gradient boosted trees.",
      videoUrl: "https://www.youtube.com/watch?v=J4Wdy0Wc_xQ",
      hasCodingContent: true,
      notes:
        "Ensemble methods combine many weak learners to create powerful models; Random Forest uses bagging while Gradient Boosting uses sequential error correction.",
      docs: [],
      partQuiz: [
        {
          question: "What is bagging in Random Forest?",
          options: [
            "Pruning trees",
            "Training trees on random bootstrap subsets",
            "Boosting residuals",
            "Dropout",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "How does Gradient Boosting differ from Random Forest?",
          options: [
            "Random Forest uses boosting",
            "Gradient Boosting builds trees sequentially to correct errors",
            "Both are identical",
            "Gradient Boosting uses bagging",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What does feature_importances_ return?",
          options: [
            "Correlation values",
            "Relative importance of each feature",
            "P-values",
            "Weights",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What is XGBoost known for?",
          options: [
            "Image classification",
            "Fast, regularized gradient boosting",
            "Deep learning",
            "Clustering",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What is stacking in ensemble learning?",
          options: [
            "Training multiple identical models",
            "Using a meta-model to combine base model predictions",
            "Sequentially correcting residuals",
            "Bootstrap sampling",
          ],
          correct: 1,
          xp: 10,
        },
      ] as CQuizQuestion[],
      subsections: [
        {
          id: "ml-m3-p2s1",
          title: "Random Forest",
          content:
            "Random Forest builds many decision trees on random data subsets and averages predictions, reducing variance significantly.",
          codeExample:
            "from sklearn.ensemble import RandomForestClassifier\nfrom sklearn.datasets import load_iris\nfrom sklearn.model_selection import train_test_split\nX, y = load_iris(return_X_y=True)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2)\nrf = RandomForestClassifier(n_estimators=100, random_state=42)\nrf.fit(X_tr, y_tr)\nprint('Accuracy:', rf.score(X_te, y_te))\nprint('Feature importances:', rf.feature_importances_.round(3))",
          video: { youtubeId: "J4Wdy0Wc_xQ", title: "Random Forest" },
          flowchart: "compilation-pipeline",
        },
        {
          id: "ml-m3-p2s2",
          title: "Gradient Boosting",
          content:
            "Gradient Boosting trains trees sequentially; each tree corrects errors of the previous. Learning rate controls how much each tree contributes.",
          codeExample:
            "from sklearn.ensemble import GradientBoostingClassifier\nfrom sklearn.datasets import load_iris\nfrom sklearn.model_selection import train_test_split\nX, y = load_iris(return_X_y=True)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2)\ngb = GradientBoostingClassifier(n_estimators=100, learning_rate=0.1, max_depth=3)\ngb.fit(X_tr, y_tr)\nprint('GB Accuracy:', gb.score(X_te, y_te))",
          video: { youtubeId: "J4Wdy0Wc_xQ", title: "Gradient Boosting" },
          flowchart: "if-else",
        },
        {
          id: "ml-m3-p2s3",
          title: "Hyperparameter Tuning",
          content:
            "GridSearchCV exhaustively tries combinations. RandomizedSearchCV samples efficiently. Both use cross-validation to find optimal hyperparameters.",
          codeExample:
            "from sklearn.model_selection import GridSearchCV\nfrom sklearn.ensemble import RandomForestClassifier\nfrom sklearn.datasets import load_iris\nX, y = load_iris(return_X_y=True)\nparam_grid = {'n_estimators': [50, 100, 200], 'max_depth': [3, 5, None]}\ngrid = GridSearchCV(RandomForestClassifier(), param_grid, cv=5, n_jobs=-1)\ngrid.fit(X, y)\nprint('Best params:', grid.best_params_)\nprint('Best score: ', grid.best_score_.round(3))",
          video: { youtubeId: "J4Wdy0Wc_xQ", title: "Hyperparameter Tuning" },
          flowchart: "loop",
        },
      ],
    },
    {
      id: "ml-m3-p3",
      title: "Part 3: Clustering & Dimensionality Reduction",
      description: "K-Means, PCA, and anomaly detection algorithms.",
      videoUrl: "https://www.youtube.com/watch?v=4b5d3muPQmA",
      hasCodingContent: true,
      notes:
        "Unsupervised techniques discover structure in unlabeled data: clustering groups similar points, PCA reduces dimensions, isolation forest detects outliers.",
      docs: [],
      partQuiz: [
        {
          question: "What does K-Means minimize?",
          options: [
            "Entropy",
            "Inertia (sum of squared distances to centroid)",
            "Silhouette score",
            "Variance",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What is the elbow method used for?",
          options: [
            "Feature selection",
            "Choosing optimal k in K-Means",
            "Scaling data",
            "Evaluating supervised models",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What does PCA reduce?",
          options: ["Samples", "Features / dimensions", "Labels", "Model size"],
          correct: 1,
          xp: 10,
        },
        {
          question: "Should you scale before PCA?",
          options: [
            "No, never",
            "Yes, always standardize first",
            "Only for regression",
            "Only for large datasets",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What score does Isolation Forest assign to anomalies?",
          options: ["Positive (+1)", "Negative (-1)", "Zero", "Greater than 1"],
          correct: 1,
          xp: 10,
        },
      ] as CQuizQuestion[],
      subsections: [
        {
          id: "ml-m3-p3s1",
          title: "K-Means Clustering",
          content:
            "K-Means: initialize k centroids, assign points to nearest centroid, recompute centroids, repeat until convergence. Use elbow method to choose k.",
          codeExample:
            "from sklearn.cluster import KMeans\nfrom sklearn.datasets import make_blobs\nimport numpy as np\nX, _ = make_blobs(n_samples=300, centers=3, random_state=42)\nkmeans = KMeans(n_clusters=3, random_state=42)\nkmeans.fit(X)\nprint('Labels:', kmeans.labels_[:10])\nprint('Centroids:\\n', kmeans.cluster_centers_.round(2))\nprint('Inertia:', kmeans.inertia_.round(2))",
          video: { youtubeId: "4b5d3muPQmA", title: "K-Means" },
          flowchart: "loop",
        },
        {
          id: "ml-m3-p3s2",
          title: "PCA for Dimensionality Reduction",
          content:
            "PCA transforms features into principal components ordered by variance explained. Scale first, then choose components retaining 95%+ variance.",
          codeExample:
            "from sklearn.decomposition import PCA\nfrom sklearn.preprocessing import StandardScaler\nfrom sklearn.datasets import load_iris\nimport numpy as np\nX, y = load_iris(return_X_y=True)\nX_s = StandardScaler().fit_transform(X)\npca = PCA(n_components=2)\nX_pca = pca.fit_transform(X_s)\nprint('Original shape:', X.shape)\nprint('Reduced shape:', X_pca.shape)\nprint('Variance explained:', pca.explained_variance_ratio_.round(3))",
          video: { youtubeId: "4b5d3muPQmA", title: "PCA" },
          flowchart: "compilation-pipeline",
        },
        {
          id: "ml-m3-p3s3",
          title: "Anomaly Detection with Isolation Forest",
          content:
            "Isolation Forest isolates anomalies by randomly partitioning data; anomalies need fewer splits and receive a label of -1.",
          codeExample:
            "from sklearn.ensemble import IsolationForest\nimport numpy as np\nnp.random.seed(42)\nX_normal = np.random.normal(0, 1, (100, 2))\nX_anom = np.array([[5, 5], [-5, 5], [5, -5]])\nX = np.vstack([X_normal, X_anom])\nif_ = IsolationForest(contamination=0.03, random_state=42)\npreds = if_.fit_predict(X)\nprint('Anomalies detected:', (preds == -1).sum())",
          video: { youtubeId: "4b5d3muPQmA", title: "Isolation Forest" },
          flowchart: "if-else",
        },
      ],
    },
  ],
  moduleQuiz: [
    {
      question: "What is bagging?",
      options: [
        "Training on full dataset repeatedly",
        "Training trees on random bootstrap subsets and averaging",
        "Sequential error correction",
        "Feature elimination",
      ],
      correct: 1,
      xp: 10,
    },
    {
      question: "Which SVM kernel is best for non-linear data?",
      options: ["Linear", "RBF", "Constant", "Always polynomial"],
      correct: 1,
      xp: 10,
    },
    {
      question: "What does Isolation Forest predict for outliers?",
      options: ["1", "0", "-1", "NaN"],
      correct: 2,
      xp: 10,
    },
    {
      question: "Why must you scale features before SVM?",
      options: [
        "To speed training only",
        "SVM is sensitive to feature magnitude; unscaled features distort margins",
        "To remove nulls",
        "To encode categories",
      ],
      correct: 1,
      xp: 10,
    },
    {
      question: "What does GridSearchCV return as best_params_?",
      options: [
        "Training accuracy",
        "Hyperparameter combination with highest CV score",
        "Loss value",
        "Feature importances",
      ],
      correct: 1,
      xp: 10,
    },
  ] as CQuizQuestion[],
  moduleTest: [
    {
      id: "ml-m3-test1",
      title: "Compare SVM, Random Forest & Gradient Boosting",
      description:
        "Train SVC (RBF kernel), RandomForestClassifier (100 trees), and GradientBoostingClassifier on the Iris dataset. Print test accuracy for each.",
      starterCode:
        "from sklearn.svm import SVC\nfrom sklearn.ensemble import RandomForestClassifier, GradientBoostingClassifier\nfrom sklearn.preprocessing import StandardScaler\nfrom sklearn.pipeline import Pipeline\nfrom sklearn.datasets import load_iris\nfrom sklearn.model_selection import train_test_split\n\nX, y = load_iris(return_X_y=True)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2, random_state=42)\n\n# Train each model and print accuracy\n",
      hints: [
        "SVC needs scaling: Pipeline([('scaler', StandardScaler()), ('svm', SVC())])",
        "RandomForestClassifier(n_estimators=100, random_state=42)",
        "Use .fit(X_tr, y_tr).score(X_te, y_te) for each",
      ],
    },
  ] as CTestProblem[],
};

// ─── Module 4: Neural Networks & Deep Learning ────────────────────────────────

const ml_module4: CModule = {
  id: "ml-neural-networks",
  title: "Module 4: Neural Networks",
  outcome:
    "Understand neural networks, backpropagation, CNNs, RNNs, and deep learning fundamentals.",
  isLocked: true,
  quizAfterModule: true,
  parts: [
    {
      id: "ml-m4-p1",
      title: "Part 1: Neural Networks",
      description: "Layers, backpropagation, and training with Keras.",
      videoUrl: "https://www.youtube.com/watch?v=aircAruvnKk",
      hasCodingContent: true,
      notes:
        "Neural networks stack layers of weighted connections; backpropagation computes gradients to minimize loss.",
      docs: [],
      partQuiz: [
        {
          question: "What does a hidden layer do?",
          options: [
            "Stores data",
            "Learns intermediate representations",
            "Outputs predictions",
            "Normalizes input",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What is backpropagation?",
          options: [
            "Forward pass",
            "Computing gradients via chain rule",
            "Dropout",
            "Batch normalization",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What loss function is used for binary classification?",
          options: [
            "MSE",
            "Binary cross-entropy",
            "Categorical cross-entropy",
            "Hinge loss",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What does Dropout do during training?",
          options: [
            "Adds noise",
            "Randomly zeros out neurons",
            "Normalizes activations",
            "Clips gradients",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What is an epoch?",
          options: [
            "One batch update",
            "One full pass through training data",
            "Validation step",
            "Learning rate cycle",
          ],
          correct: 1,
          xp: 10,
        },
      ] as CQuizQuestion[],
      subsections: [
        {
          id: "ml-m4-p1s1",
          title: "Building a Neural Network",
          content:
            "Stack Dense layers with activation functions. Compile with optimizer and loss. Train with model.fit().",
          codeExample:
            "# Keras sequential model (conceptual)\n# from tensorflow import keras\n# model = keras.Sequential([\n#     keras.layers.Dense(64, activation='relu', input_shape=(4,)),\n#     keras.layers.Dense(32, activation='relu'),\n#     keras.layers.Dense(3, activation='softmax')\n# ])\n# model.compile(optimizer='adam', loss='sparse_categorical_crossentropy', metrics=['accuracy'])\n# model.fit(X_train, y_train, epochs=20, validation_split=0.2)\nprint('Neural network: Dense(64) -> Dense(32) -> Dense(3, softmax)')",
          video: { youtubeId: "aircAruvnKk", title: "Neural Networks" },
          flowchart: "compilation-pipeline",
        },
        {
          id: "ml-m4-p1s2",
          title: "Backpropagation",
          content:
            "Backprop computes dL/dW for each layer via chain rule, then optimizer updates weights W = W - lr * dL/dW.",
          codeExample:
            "# Manual backprop for 1-layer network\nimport numpy as np\nnp.random.seed(42)\nX = np.array([[0,0],[0,1],[1,0],[1,1]])\ny = np.array([[0],[1],[1],[0]])  # XOR\nW = np.random.randn(2, 1) * 0.1\nb = np.zeros((1,))\nfor _ in range(1000):\n    pred = 1 / (1 + np.exp(-(X @ W + b)))\n    loss = -np.mean(y * np.log(pred+1e-7) + (1-y) * np.log(1-pred+1e-7))\n    dW = X.T @ (pred - y) / len(X)\n    W -= 0.1 * dW\nprint('Final loss:', loss.round(4))",
          video: { youtubeId: "aircAruvnKk", title: "Backpropagation" },
          flowchart: "loop",
        },
        {
          id: "ml-m4-p1s3",
          title: "Regularization in NNs",
          content:
            "Dropout randomly deactivates neurons during training. L2 weight decay penalizes large weights. Both reduce overfitting.",
          codeExample:
            "# Keras with Dropout (conceptual)\n# model = keras.Sequential([\n#     keras.layers.Dense(128, activation='relu'),\n#     keras.layers.Dropout(0.3),\n#     keras.layers.Dense(64, activation='relu'),\n#     keras.layers.Dropout(0.3),\n#     keras.layers.Dense(1, activation='sigmoid')\n# ])\n# model.compile(optimizer='adam', loss='binary_crossentropy')\nprint('Dropout(0.3) drops 30% of neurons each training step')",
          video: { youtubeId: "aircAruvnKk", title: "Regularization" },
          flowchart: "if-else",
        },
      ],
    },
    {
      id: "ml-m4-p2",
      title: "Part 2: CNNs",
      description: "Convolutional Neural Networks for image recognition.",
      videoUrl: "https://www.youtube.com/watch?v=YRhxdVk_sIs",
      hasCodingContent: true,
      notes:
        "CNNs use convolutional filters to detect local patterns in images, enabling translation-invariant feature learning.",
      docs: [],
      partQuiz: [
        {
          question: "What does a convolutional filter detect?",
          options: [
            "Global patterns",
            "Local spatial patterns",
            "Temporal patterns",
            "Color histograms",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What is max pooling used for?",
          options: [
            "Increase feature map size",
            "Downsample and retain strong activations",
            "Add non-linearity",
            "Normalize features",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What is the purpose of Flatten in a CNN?",
          options: [
            "Reduce channels",
            "Convert 2D feature maps to 1D vector",
            "Apply dropout",
            "Add batch norm",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What does transfer learning reuse?",
          options: [
            "Training data",
            "Pre-trained model weights",
            "Loss function",
            "Optimizer state",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "Which architecture won ImageNet 2012?",
          options: ["VGG", "AlexNet", "ResNet", "LeNet"],
          correct: 1,
          xp: 10,
        },
      ] as CQuizQuestion[],
      subsections: [
        {
          id: "ml-m4-p2s1",
          title: "CNN Architecture",
          content:
            "CNN = Conv2D → ReLU → MaxPool (repeated) → Flatten → Dense. Each conv layer detects increasingly complex patterns.",
          codeExample:
            "# Keras CNN for image classification (conceptual)\n# model = keras.Sequential([\n#     keras.layers.Conv2D(32, (3,3), activation='relu', input_shape=(28,28,1)),\n#     keras.layers.MaxPooling2D((2,2)),\n#     keras.layers.Conv2D(64, (3,3), activation='relu'),\n#     keras.layers.MaxPooling2D((2,2)),\n#     keras.layers.Flatten(),\n#     keras.layers.Dense(64, activation='relu'),\n#     keras.layers.Dense(10, activation='softmax')\n# ])\nprint('CNN: Conv → Pool → Conv → Pool → Flatten → Dense')",
          video: { youtubeId: "YRhxdVk_sIs", title: "CNN Architecture" },
          flowchart: "compilation-pipeline",
        },
        {
          id: "ml-m4-p2s2",
          title: "Feature Maps & Pooling",
          content:
            "Convolving a 32×32 image with a 3×3 filter produces a 30×30 feature map. MaxPool(2×2) halves spatial dimensions.",
          codeExample:
            "import numpy as np\n# Simulate 2D convolution\ndef conv2d(image, kernel):\n    kh, kw = kernel.shape\n    oh, ow = image.shape[0]-kh+1, image.shape[1]-kw+1\n    out = np.zeros((oh, ow))\n    for i in range(oh):\n        for j in range(ow):\n            out[i,j] = np.sum(image[i:i+kh, j:j+kw] * kernel)\n    return out\nimg = np.random.rand(5, 5)\nkern = np.array([[0,-1,0],[-1,4,-1],[0,-1,0]])  # edge filter\nprint('Output shape:', conv2d(img, kern).shape)",
          video: { youtubeId: "YRhxdVk_sIs", title: "Convolutions" },
          flowchart: "loop",
        },
        {
          id: "ml-m4-p2s3",
          title: "Transfer Learning",
          content:
            "Load a pretrained model (ResNet, VGG), freeze base layers, replace the head, train only the new layers on your dataset.",
          codeExample:
            "# Transfer learning with MobileNet (conceptual)\n# import tensorflow as tf\n# base = tf.keras.applications.MobileNetV2(input_shape=(224,224,3),\n#     include_top=False, weights='imagenet')\n# base.trainable = False\n# model = tf.keras.Sequential([\n#     base,\n#     tf.keras.layers.GlobalAveragePooling2D(),\n#     tf.keras.layers.Dense(2, activation='softmax')\n# ])\nprint('Transfer learning: pretrained base + custom head')",
          video: { youtubeId: "YRhxdVk_sIs", title: "Transfer Learning" },
          flowchart: "if-else",
        },
      ],
    },
    {
      id: "ml-m4-p3",
      title: "Part 3: RNNs",
      description: "Recurrent networks for sequences and time series.",
      videoUrl: "https://www.youtube.com/watch?v=LHXXI4-IEns",
      hasCodingContent: true,
      notes:
        "RNNs process sequential data by maintaining hidden state across time steps; LSTMs solve the vanishing gradient problem.",
      docs: [],
      partQuiz: [
        {
          question: "What makes RNNs suitable for sequences?",
          options: [
            "Convolutional filters",
            "Hidden state passed across timesteps",
            "Attention mechanism",
            "Pooling layers",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What problem do LSTMs solve?",
          options: [
            "Overfitting",
            "Vanishing gradient in long sequences",
            "Class imbalance",
            "High dimensionality",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What does return_sequences=True do in LSTM?",
          options: [
            "Returns last state only",
            "Returns output at every timestep",
            "Stacks LSTM layers",
            "Resets state",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "Which architecture uses attention instead of RNN?",
          options: ["CNN", "Transformer", "Autoencoder", "GAN"],
          correct: 1,
          xp: 10,
        },
        {
          question: "What is BPTT?",
          options: [
            "Back Propagation Through Time",
            "Batch Processing of Training Tasks",
            "Binary Prediction Tree",
            "Bidirectional Training",
          ],
          correct: 0,
          xp: 10,
        },
      ] as CQuizQuestion[],
      subsections: [
        {
          id: "ml-m4-p3s1",
          title: "RNN Basics",
          content:
            "An RNN cell takes (input, hidden_state) and outputs new hidden state, enabling memory of previous inputs in a sequence.",
          codeExample:
            "import numpy as np\n# Simple RNN cell\ndef rnn_cell(x, h, Wx, Wh, b):\n    return np.tanh(Wx @ x + Wh @ h + b)\nnp.random.seed(0)\nWx, Wh, b = np.random.randn(4,3), np.random.randn(4,4), np.zeros(4)\nh = np.zeros(4)\nsequence = [np.random.randn(3) for _ in range(5)]\nfor t, x in enumerate(sequence):\n    h = rnn_cell(x, h, Wx, Wh, b)\n    print(f't={t}: h={h.round(2)}')",
          video: { youtubeId: "LHXXI4-IEns", title: "RNN Basics" },
          flowchart: "loop",
        },
        {
          id: "ml-m4-p3s2",
          title: "LSTM Architecture",
          content:
            "LSTM adds forget, input, output gates to control what to remember/forget, allowing gradients to flow through long sequences.",
          codeExample:
            "# Keras LSTM for sequence classification (conceptual)\n# model = keras.Sequential([\n#     keras.layers.Embedding(vocab_size, 64),\n#     keras.layers.LSTM(64, return_sequences=True),\n#     keras.layers.LSTM(32),\n#     keras.layers.Dense(1, activation='sigmoid')\n# ])\n# model.compile(optimizer='adam', loss='binary_crossentropy')\nprint('LSTM gates: forget, input, output — each controlled by sigmoid')",
          video: { youtubeId: "LHXXI4-IEns", title: "LSTM" },
          flowchart: "if-else",
        },
        {
          id: "ml-m4-p3s3",
          title: "Time Series Forecasting",
          content:
            "Reshape time series into sliding windows (X: past n steps, y: next step). Train LSTM to predict the next value.",
          codeExample:
            "import numpy as np\n# Create sliding window dataset\ndef create_dataset(data, window=5):\n    X, y = [], []\n    for i in range(len(data) - window):\n        X.append(data[i:i+window])\n        y.append(data[i+window])\n    return np.array(X), np.array(y)\nts = np.sin(np.linspace(0, 20, 200))\nX, y = create_dataset(ts, window=10)\nprint('X shape:', X.shape, 'y shape:', y.shape)",
          video: { youtubeId: "LHXXI4-IEns", title: "Time Series" },
          flowchart: "compilation-pipeline",
        },
      ],
    },
  ],
  moduleQuiz: [
    {
      question: "What does Dropout(0.5) do?",
      options: [
        "Halves learning rate",
        "Drops 50% of neurons randomly during training",
        "Halves batch size",
        "Normalizes by 0.5",
      ],
      correct: 1,
      xp: 10,
    },
    {
      question: "What is the role of Conv2D in a CNN?",
      options: [
        "Flatten features",
        "Detect local spatial patterns",
        "Downsample activations",
        "Apply fully-connected weights",
      ],
      correct: 1,
      xp: 10,
    },
    {
      question: "What solves vanishing gradient in RNNs?",
      options: ["Dropout", "Batch Normalization", "LSTM gates", "ReLU only"],
      correct: 2,
      xp: 10,
    },
    {
      question: "What is transfer learning?",
      options: [
        "Training from scratch",
        "Reusing pretrained model weights",
        "Data augmentation",
        "Ensemble learning",
      ],
      correct: 1,
      xp: 10,
    },
    {
      question: "What does binary cross-entropy measure?",
      options: [
        "Regression error",
        "Log loss for binary classification",
        "Distance between centroids",
        "Gradient norm",
      ],
      correct: 1,
      xp: 10,
    },
  ] as CQuizQuestion[],
  moduleTest: [
    {
      id: "ml-m4-test1",
      title: "Sliding Window for Time Series",
      description:
        "Write a function create_sequences(data, window) that returns X (shape: samples x window) and y (next value). Test with a sine wave of 100 points and window=10.",
      starterCode:
        "import numpy as np\n\ndef create_sequences(data, window):\n    X, y = [], []\n    # Your code: loop and append windows\n    return np.array(X), np.array(y)\n\ndata = np.sin(np.linspace(0, 10, 100))\nX, y = create_sequences(data, window=10)\nprint('X shape:', X.shape)  # expect (90, 10)\nprint('y shape:', y.shape)  # expect (90,)\n",
      hints: [
        "Loop i from 0 to len(data) - window",
        "X.append(data[i:i+window]) and y.append(data[i+window])",
        "Return np.array(X), np.array(y)",
      ],
    },
  ] as CTestProblem[],
};

// ─── Module 5: ML Project ─────────────────────────────────────────────────────

const ml_module5: CModule = {
  id: "ml-project",
  title: "Module 5: ML Project",
  outcome:
    "Build an end-to-end ML project: data collection → preprocessing → training → evaluation → deployment.",
  isLocked: true,
  quizAfterModule: true,
  parts: [
    {
      id: "ml-m5-p1",
      title: "Part 1: Data Pipeline & Model Training",
      description:
        "Build a complete data pipeline: collect, clean, feature engineer, and train a model.",
      videoUrl: "https://www.youtube.com/watch?v=b3G9IUGFv2A",
      hasCodingContent: true,
      notes:
        "A production ML project starts with a solid data pipeline: load data, handle missing values, encode features, scale, split, and train a model end-to-end.",
      docs: [],
      partQuiz: [
        {
          question: "Which Python library saves sklearn models?",
          options: ["pickle only", "joblib or pickle", "json", "yaml"],
          correct: 1,
          xp: 10,
        },
        {
          question: "What is a REST API?",
          options: [
            "Database query language",
            "HTTP-based interface for services",
            "Model training loop",
            "Feature pipeline",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What format is best for serving predictions?",
          options: ["CSV", "JSON", "Binary", "XML always"],
          correct: 1,
          xp: 10,
        },
        {
          question: "What does model versioning help with?",
          options: [
            "Training speed",
            "Rolling back to previous model versions",
            "Feature engineering",
            "Data cleaning",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What is model drift?",
          options: [
            "Slow training",
            "Model accuracy degrading as data distribution changes",
            "Memory leak",
            "Version conflict",
          ],
          correct: 1,
          xp: 10,
        },
      ] as CQuizQuestion[],
      subsections: [
        {
          id: "ml-m5-p1s1",
          title: "Saving & Loading Models",
          content:
            "Use joblib.dump() to save and joblib.load() to restore. Always save the preprocessor alongside the model.",
          codeExample:
            "import joblib\nfrom sklearn.pipeline import Pipeline\nfrom sklearn.preprocessing import StandardScaler\nfrom sklearn.svm import SVC\nfrom sklearn.datasets import load_iris\n\nX, y = load_iris(return_X_y=True)\npipe = Pipeline([('scaler', StandardScaler()), ('svm', SVC())])\npipe.fit(X, y)\n\njoblib.dump(pipe, 'model.joblib')\nloaded = joblib.load('model.joblib')\nprint('Loaded prediction:', loaded.predict(X[:1]))",
          video: { youtubeId: "b3G9IUGFv2A", title: "Saving Models" },
          flowchart: "compilation-pipeline",
        },
        {
          id: "ml-m5-p1s2",
          title: "Flask API for ML",
          content:
            "Create a /predict endpoint that receives JSON features, loads the model, returns predictions as JSON.",
          codeExample:
            "# Flask ML API (conceptual)\n# from flask import Flask, request, jsonify\n# import joblib\n# import numpy as np\n#\n# app = Flask(__name__)\n# model = joblib.load('model.joblib')\n#\n# @app.route('/predict', methods=['POST'])\n# def predict():\n#     data = request.json['features']\n#     pred = model.predict([data])\n#     return jsonify({'prediction': int(pred[0])})\n#\n# if __name__ == '__main__':\n#     app.run(port=5000)\nprint('POST /predict -> {features: [1.2, 3.4, 5.6, 7.8]} -> {prediction: 0}')",
          video: { youtubeId: "b3G9IUGFv2A", title: "Flask API" },
          flowchart: "if-else",
        },
        {
          id: "ml-m5-p1s3",
          title: "Docker for ML",
          content:
            "Containerize your ML app with Docker: Dockerfile specifies Python version, installs dependencies, copies code, runs the server.",
          codeExample:
            '# Dockerfile for ML API\n# FROM python:3.11-slim\n# WORKDIR /app\n# COPY requirements.txt .\n# RUN pip install -r requirements.txt\n# COPY . .\n# EXPOSE 5000\n# CMD ["python", "app.py"]\n\n# Build and run:\n# docker build -t ml-api .\n# docker run -p 5000:5000 ml-api\nprint(\'Docker packages app + dependencies into a portable container\')',
          video: { youtubeId: "b3G9IUGFv2A", title: "Docker for ML" },
          flowchart: "loop",
        },
      ],
    },
    {
      id: "ml-m5-p2",
      title: "Part 2: Model Evaluation & Improvement",
      description:
        "Evaluate model quality, diagnose errors, and improve performance.",
      videoUrl: "https://www.youtube.com/watch?v=NgWujOrCZFo",
      hasCodingContent: true,
      notes:
        "Model evaluation goes beyond accuracy: use cross-validation, learning curves, and bias-variance diagnosis to systematically improve your ML project.",
      docs: [],
      partQuiz: [
        {
          question: "What does MLflow track?",
          options: [
            "Docker images",
            "Experiments, parameters, metrics, artifacts",
            "Database queries",
            "Frontend deployments",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What is DVC used for?",
          options: [
            "Model training",
            "Data versioning",
            "API deployment",
            "Hyperparameter search",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What is a feature store?",
          options: [
            "Cloud bucket",
            "Centralized repository of reusable features",
            "Model registry",
            "Training dataset",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What triggers retraining in MLOps?",
          options: [
            "Random schedule only",
            "Data drift or performance degradation",
            "Manual only",
            "Version bump",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What is A/B testing in ML deployment?",
          options: [
            "Unit testing models",
            "Routing traffic to compare model versions",
            "Cross-validation",
            "Hyperparameter tuning",
          ],
          correct: 1,
          xp: 10,
        },
      ] as CQuizQuestion[],
      subsections: [
        {
          id: "ml-m5-p2s1",
          title: "Experiment Tracking with MLflow",
          content:
            "MLflow.start_run() logs parameters, metrics, and artifacts. Compare runs in the MLflow UI to select the best model.",
          codeExample:
            "# MLflow experiment tracking (conceptual)\n# import mlflow\n# from sklearn.ensemble import RandomForestClassifier\n# from sklearn.datasets import load_iris\n# from sklearn.model_selection import cross_val_score\n#\n# X, y = load_iris(return_X_y=True)\n# with mlflow.start_run():\n#     n_est = 100\n#     mlflow.log_param('n_estimators', n_est)\n#     rf = RandomForestClassifier(n_estimators=n_est)\n#     score = cross_val_score(rf, X, y, cv=5).mean()\n#     mlflow.log_metric('cv_accuracy', score)\n#     print('Logged run with accuracy:', score)\nprint('MLflow: log_param + log_metric + log_artifact per run')",
          video: { youtubeId: "NgWujOrCZFo", title: "MLflow" },
          flowchart: "compilation-pipeline",
        },
        {
          id: "ml-m5-p2s2",
          title: "Data Versioning with DVC",
          content:
            "DVC tracks large data files in Git using pointers. dvc add data.csv → git commit tracks the data version without storing it in Git.",
          codeExample:
            "# DVC workflow (terminal commands, conceptual)\n# git init && dvc init\n# dvc add data/train.csv      # creates data/train.csv.dvc\n# git add data/train.csv.dvc .gitignore\n# git commit -m 'track training data v1'\n# dvc push                    # push data to remote storage\n# dvc pull                    # restore data on another machine\nprint('DVC: version data like Git versions code')",
          video: { youtubeId: "NgWujOrCZFo", title: "DVC" },
          flowchart: "if-else",
        },
        {
          id: "ml-m5-p2s3",
          title: "Model Monitoring",
          content:
            "Monitor prediction drift (output distribution shift) and data drift (input distribution shift) to trigger automated retraining.",
          codeExample:
            "import numpy as np\nfrom scipy import stats\n\ndef detect_drift(reference, production, threshold=0.05):\n    stat, p_value = stats.ks_2samp(reference, production)\n    drift = p_value < threshold\n    return drift, p_value\n\nreference = np.random.normal(0, 1, 1000)\nproduction_ok = np.random.normal(0, 1, 200)\nproduction_drifted = np.random.normal(2, 1, 200)\n\nprint('No drift:', detect_drift(reference, production_ok))\nprint('Drift detected:', detect_drift(reference, production_drifted))",
          video: { youtubeId: "NgWujOrCZFo", title: "Model Monitoring" },
          flowchart: "loop",
        },
      ],
    },
    {
      id: "ml-m5-p3",
      title: "Part 3: Model Deployment & Serving",
      description:
        "Save, version, and serve your trained ML model as a REST API.",
      videoUrl: "https://www.youtube.com/watch?v=GJsBTnJjuSU",
      hasCodingContent: true,
      notes:
        "The final step of an ML project is deployment: save the model with joblib, wrap it in a Flask/FastAPI endpoint, containerize with Docker, and monitor in production.",
      docs: [],
      partQuiz: [
        {
          question: "What is EDA?",
          options: [
            "Model evaluation",
            "Exploratory Data Analysis",
            "External Data Augmentation",
            "Ensemble Design Architecture",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What is feature engineering?",
          options: [
            "Collecting data",
            "Creating new features from existing ones",
            "Normalizing input",
            "Removing features",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What is a Kaggle kernel/notebook?",
          options: [
            "Python package",
            "Cloud-hosted code environment",
            "Dataset format",
            "Submission type",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What is ensembling in Kaggle?",
          options: [
            "Submitting one model",
            "Combining predictions from multiple models",
            "Cross-validation only",
            "Data leakage",
          ],
          correct: 1,
          xp: 10,
        },
        {
          question: "What metric is common in classification competitions?",
          options: ["MSE", "R²", "ROC-AUC", "RMSE"],
          correct: 2,
          xp: 10,
        },
      ] as CQuizQuestion[],
      subsections: [
        {
          id: "ml-m5-p3s1",
          title: "EDA Workflow",
          content:
            "EDA: check shape, dtypes, nulls, distributions, correlations, and target balance before modeling.",
          codeExample:
            "import pandas as pd\nimport numpy as np\n\nnp.random.seed(42)\ndf = pd.DataFrame({\n    'age': np.random.randint(18, 65, 200),\n    'income': np.random.normal(50000, 15000, 200),\n    'score': np.random.rand(200),\n    'target': np.random.randint(0, 2, 200)\n})\n\nprint('Shape:', df.shape)\nprint('Nulls:\\n', df.isnull().sum())\nprint('Target balance:\\n', df['target'].value_counts(normalize=True))\nprint('Numeric stats:\\n', df.describe().round(2))",
          video: { youtubeId: "GJsBTnJjuSU", title: "EDA" },
          flowchart: "compilation-pipeline",
        },
        {
          id: "ml-m5-p3s2",
          title: "Feature Engineering",
          content:
            "Create interaction features, log-transform skewed columns, encode categoricals with label/one-hot encoding.",
          codeExample:
            "import pandas as pd\nimport numpy as np\n\ndf = pd.DataFrame({\n    'price': [100, 10000, 500, 50000, 200],\n    'category': ['A', 'B', 'A', 'C', 'B'],\n    'age': [1, 5, 2, 10, 3]\n})\n\n# Log transform skewed feature\ndf['log_price'] = np.log1p(df['price'])\n\n# Interaction feature\ndf['price_per_age'] = df['price'] / df['age']\n\n# One-hot encode\ndf = pd.get_dummies(df, columns=['category'])\nprint(df.head())",
          video: { youtubeId: "GJsBTnJjuSU", title: "Feature Engineering" },
          flowchart: "if-else",
        },
        {
          id: "ml-m5-p3s3",
          title: "Ensembling & Submission",
          content:
            "Average or stack predictions from multiple models. Use cross-validated out-of-fold predictions to avoid leakage.",
          codeExample:
            "import numpy as np\nfrom sklearn.ensemble import RandomForestClassifier, GradientBoostingClassifier\nfrom sklearn.linear_model import LogisticRegression\nfrom sklearn.datasets import load_breast_cancer\nfrom sklearn.model_selection import cross_val_predict\nX, y = load_breast_cancer(return_X_y=True)\nmodels = [\n    RandomForestClassifier(n_estimators=50, random_state=42),\n    GradientBoostingClassifier(n_estimators=50, random_state=42),\n    LogisticRegression(max_iter=500)\n]\npreds = [cross_val_predict(m, X, y, cv=5, method='predict_proba')[:,1] for m in models]\nensemble = np.mean(preds, axis=0)\nfrom sklearn.metrics import roc_auc_score\nprint('Ensemble ROC-AUC:', roc_auc_score(y, ensemble).round(4))",
          video: { youtubeId: "GJsBTnJjuSU", title: "Ensembling" },
          flowchart: "loop",
        },
      ],
    },
  ],
  moduleQuiz: [
    {
      question: "What does joblib.dump() do?",
      options: [
        "Trains model",
        "Saves model to disk",
        "Deletes model",
        "Evaluates model",
      ],
      correct: 1,
      xp: 10,
    },
    {
      question: "What does MLflow log_metric track?",
      options: [
        "Source code",
        "Numerical performance metrics per run",
        "Data files",
        "Docker images",
      ],
      correct: 1,
      xp: 10,
    },
    {
      question: "What is model drift?",
      options: [
        "Slow inference",
        "Accuracy degradation due to data distribution change",
        "Memory issue",
        "Version conflict",
      ],
      correct: 1,
      xp: 10,
    },
    {
      question: "What is log1p transformation used for?",
      options: [
        "Encoding categories",
        "Reducing skewness in positive features",
        "Normalizing labels",
        "Removing outliers",
      ],
      correct: 1,
      xp: 10,
    },
    {
      question: "What is ensembling?",
      options: [
        "Single best model",
        "Combining multiple model predictions",
        "Cross-validation",
        "Hyperparameter tuning",
      ],
      correct: 1,
      xp: 10,
    },
  ] as CQuizQuestion[],
  moduleTest: [
    {
      id: "ml-m5-test1",
      title: "End-to-End ML Pipeline",
      description:
        "On the breast cancer dataset: split data, build a Pipeline (StandardScaler + RandomForest), compute 5-fold CV accuracy, save with joblib, reload and predict on test set.",
      starterCode:
        "import joblib\nfrom sklearn.pipeline import Pipeline\nfrom sklearn.preprocessing import StandardScaler\nfrom sklearn.ensemble import RandomForestClassifier\nfrom sklearn.datasets import load_breast_cancer\nfrom sklearn.model_selection import train_test_split, cross_val_score\n\nX, y = load_breast_cancer(return_X_y=True)\nX_tr, X_te, y_tr, y_te = train_test_split(X, y, test_size=0.2, random_state=42)\n\n# 1. Build Pipeline\n# 2. Run 5-fold CV, print mean accuracy\n# 3. Save pipeline to 'ml_pipeline.joblib'\n# 4. Load and print test accuracy\n",
      hints: [
        "Pipeline([('scaler', StandardScaler()), ('rf', RandomForestClassifier())])",
        "cross_val_score(pipe, X_tr, y_tr, cv=5).mean()",
        "joblib.dump(pipe, 'ml_pipeline.joblib'); loaded = joblib.load('ml_pipeline.joblib')",
      ],
    },
  ] as CTestProblem[],
};

// ─── Course Assembly ───────────────────────────────────────────────────────────

export const ML_COURSE = {
  id: "machine-learning-course",
  name: "Machine Learning",
  modules: [
    ml_module0,
    ml_module1,
    ml_module2,
    ml_module3,
    ml_module4,
    ml_module5,
  ],
  certificate: {
    title: "Machine Learning Certificate",
    description:
      "Awarded for completing all 5 modules of the Machine Learning course.",
  },
};

export const ML_ROADMAP_ENTRY = {
  id: "machine-learning-course",
  title: "Machine Learning",
  icon: "🤖",
  color: "from-purple-500/20 to-pink-500/10",
  tagColor: "text-purple-400 bg-purple-500/10 border-purple-500/20",
  description: "Master ML algorithms, deep learning, and model deployment.",
  topics: [] as [],
  isCourse: true as const,
  certificate: { title: "Machine Learning Certificate" },
};
