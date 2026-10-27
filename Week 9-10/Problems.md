1. Which of the following precision-recall curves represents the best outcome?  What can be said about which threshold(s) are the highest thresholds (indicated by the dot on the curve)?.  Explain. 

<img width="491" height="391" alt="Image" src="https://github.com/user-attachments/assets/43e145a4-1de3-4f21-a01a-370ff68d17c1" />

2. Which of the following ROC-AUC curves represents the best outcome?  What can be said about which threshold(s) are the highest thresholds (indicated by the dot on the curve)?.  Explain.

<img width="491" height="382" alt="Image" src="https://github.com/user-attachments/assets/7de57cb3-0185-4647-9457-4eaf73b0df5d" />

3. Prompt 
 
You are training a machine learning model to predict customer churn, but the model performs extremely well on the training data and poorly on the validation data. You write an LLM prompt asking it to explain whether this problem is likely due to high variance, how regularization could help, and how to choose between simpler and more complex models. The goal is to understand the tradeoff between fitting the data closely and building a model that generalizes well to new customers. 
 
Below are five potential prompts (shuffled) that you could provide to an LLM to perform this task. 
 
X - “I trained a customer churn model and got high training accuracy but low validation accuracy. Could this mean the model is memorizing the training data? How can I diagnose and fix the problem?”

Y - “My churn prediction model has 96% training accuracy but only 68% validation accuracy. Is this likely overfitting or a bias-variance problem? What steps should I take to improve validation performance?” 

Z -  “My machine learning model predicts customer churn very well on the data I trained it on, but it does badly on new validation data. What is going wrong, and what should I do next?” 

W -  “My customer churn classifier gets 96% training accuracy and 68% validation accuracy on a time-based validation split. It uses behavioral features, some calculated after the prediction date. Could this be overfitting or data leakage, and how should I redesign validation, features, and model tuning?”  

V -  “I trained a customer churn classifier with 96% training accuracy and 68% validation accuracy. Please explain whether this suggests high variance/overfitting, and recommend practical fixes, such as regularization, simpler models, cross-validation, or better feature engineering.” 
