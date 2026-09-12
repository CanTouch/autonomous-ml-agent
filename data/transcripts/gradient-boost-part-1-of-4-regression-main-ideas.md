---
title: "Gradient Boost Part 1 (of 4): Regression Main Ideas"
url: "https://www.youtube.com/watch?v=3CC4N4z3GJc"
date: "2019-03-25"
video_id: "3CC4N4z3GJc"
uploader: "StatQuest with Josh Starmer"
language: "en"
---

# Gradient Boost Part 1 (of 4): Regression Main Ideas

Gradient Boost, part one. Regression main ideas. StatQuest. Hello, I'm Josh Starmer and welcome to StatQuest. Today, we're going to talk about the gradient boost machine learning algorithm. Specifically, we're going to focus on how gradient boost is used for regression. Note, this StatQuest assumes you already understand decision trees. So, if you're not already down with those, check out the quest.

This StatQuest also assumes that you are familiar with AdaBoost and the trade-off between bias and variance. If not, check out the quests. The links are in the description below. This StatQuest is the first part in a series that explains how the gradient boost machine learning algorithm works. Specifically, we'll use this data where we have the height measurements from six people, their favorite colors, their genders, and their weights.

And we'll walk through, step-by-step, the most common way that gradient boost fits a model to this training data. Note, when gradient boost is used to predict a continuous value, like weight, we say that we are using gradient boost for regression. Using gradient boost for regression is different from doing linear regression.

So, while the two methods are related, don't get them confused with each other. Part two in this series will dive deep into the math behind the gradient boost algorithm for regression, walking through it step-by-step and proving that what we covered today is correct. Part three in this series shows how gradient boost can be used for classification.

Specifically, we'll walk through, step-by-step, the most common way gradient boost can classify someone as either loving the movie Troll 2 or not loving Troll 2. Part four will return to the math behind gradient boost, this time focusing on classification, walking through it step-by-step. Note, the gradient boost algorithm looks complicated because it was designed to be configured in a wide variety of ways.

But, the reality is that 99% of the time only one configuration is used to predict continuous values like weight, and one configuration is used to classify samples into different categories. This StatQuest focuses on showing you the most common way gradient boost is used to predict a continuous value like weight.

If you are familiar with AdaBoost, then a lot of gradient boost will seem very similar. So, let's briefly compare and contrast AdaBoost and gradient boost. If we want to use these measurements to predict weight, then AdaBoost starts by building a very short tree called a stump from the training data.

And then the amount of say that the new stump has on the final output is based on how well it compensated for those previous errors. Then AdaBoost builds the next stump based on errors that the previous stump made. In this example, the new stump did a poor job compensating for the previous stump's errors, and its size reflects its reduced amount of say.

Then AdaBoost builds another stump based on the errors made by the previous stump. And this stump did a little better than the last stump, so it's a little larger. Then AdaBoost continues to make stumps in this fashion until it has made the number of stumps you asked for or it has a perfect fit.

In contrast, gradient boost starts by making a single leaf instead of a tree or stump. This leaf represents an initial guess for the weights for all of the samples. When trying to predict a continuous value like weight, the first guess is the average value. Then gradient boost builds a tree.

Like AdaBoost, this tree is based on the errors made by the previous tree. But unlike AdaBoost, this tree is usually larger than a stump. That said, gradient boost still restricts the size of the tree. In the simple example that we will go through in this stat quest, we will build trees with up to four leaves, but no larger.

However, in practice, people often set the maximum number of leaves to be between eight and 32. Thus, like AdaBoost, gradient boost builds fixed-size trees based on the previous trees' errors, but unlike AdaBoost, each tree can be larger than a stump. Also, like AdaBoost, gradient boost scales the trees. However, gradient boost scales all trees by the same amount.

Then gradient boost builds another tree based on the errors made by the previous tree. And then it scales the tree. And gradient boost continues to build trees in this fashion until it has made the number of trees you asked for or additional trees fail to improve the fit.

Now that we know the main similarities and differences between gradient boost and AdaBoost, let's see how the most common gradient boost configuration would use this training data to predict weight. The first thing we do is calculate the average weight. This is the first attempt at predicting everyone's weight.

In other words, if we stopped right now, we would predict that everyone weighed 71.2 kg. However, gradient boost doesn't stop here. The next thing we do is build a tree based on the errors from the first tree. The errors that the previous tree made are the differences between the observed weights and the predicted weight, 71.2.

So, let's start by plugging in 71.2 for the predicted weight. And then plug in the first observed weight. And do the math. And save the difference, which is called a pseudo residual, in a new column. Note, the term pseudo residual is based on linear regression, where the difference between the observed values and the predicted values results in residuals.

The pseudo part of pseudo residual is a reminder that we are doing gradient boost, not linear regression, and is something I'll talk more about in part two of this series when we go through the math. Now, we do the same thing for the remaining weights. Now, we will build a tree using height, favorite color, and gender to predict the residuals.

If it seems strange to predict the residuals instead of the original weights, just bear with me, and soon all will become clear. So, setting aside the reason why we are building a tree to predict the residuals for the time being, here's the tree. Remember, in this example, we are only allowing up to four leaves.

But when using a larger data set, it is common to allow anywhere from eight to 32. By restricting the total number of leaves, we get fewer leaves than residuals. As a result, these two rows of data go to the same leaf. So, we replace these residuals with average.

And these two rows of data go to the same leaf. So, we replace these residuals with their average. Now, we can combine the original leaf with the new tree to make a new prediction of an individual's weight from the training data. We start with the initial prediction, 71.2.

Then, we run the data down the tree, and we get 16.8. So, the predicted weight equals 71.2 + 16.8, which equals 88. Which is the same as the observed weight. Is this awesome? No. The model fits the training data too well. In other words, we have low bias, but probably very high variance.

Gradient boost deals with this problem by using a learning rate to scale the contribution from the new tree. The learning rate is a value between zero and one. In this case, we'll set the learning rate to 0.1. Now, the predicted weight equals 71.2 + 0.1 * 16.8, which equals 72.9.

With the learning rate set to 0.1, the new prediction isn't as good as it was before, but it's a little better than the prediction made with just the original leaf, which predicted that all samples would weigh 71.2. In other words, scaling the tree by the learning rate results in a small step in the right direction.

According to the dude that invented gradient boost, Jerome Friedman, empirical evidence shows that taking lots of small steps in the right direction results in better predictions with a testing data set, i.e. lower variance. Bam! So, let's build another tree so we can take another small step in the right direction.

Just like before, we calculate the pseudo residuals, the difference between the observed weights and our latest predictions. So, we plug in the observed weight and the new predicted weight and we get 15.1. And we save that in the column for pseudo residuals. Then we repeat for all of the other individuals in the training data set.

Small bam. Note, these are the original residuals from when our prediction was simply the average overall weight. And these are the residuals after adding the new tree scaled by the learning rate. The new residuals are all smaller than before, so we've taken a small step in the right direction.

Double bam! Now, let's build a new tree to predict the new residuals. And here's the new tree. Note, in this simple example, the branches are the same as before. However, in practice, the trees can be different each time. Just like before, since multiple samples ended up in these leaves, we just replace the residuals with their averages.

Now we combine the new tree with the previous tree and the initial leaf. Note, we scale all of the trees by the learning rate, which we set to 0.1. And add everything together. Now we're ready to make a new prediction from the training data. Just like before, we start with the initial prediction.

Then add the scaled amount from the first tree and the scaled amount from the second tree. That gives us 71.2 + 0.1 * 16.8 + 0.1 * 15.1 which equals 74.4. Which is another small step closer to the observed weight. Now we use the initial leaf plus the scaled values from the first tree plus the scaled values from the second tree to calculate new residuals.

Remember, these were the residuals from when we just used a single leaf to predict weight. And these were the residuals after we added the first tree to the prediction. And these are the residuals after we added the second tree to the prediction. Each time we add a tree to the prediction, the residuals get smaller.

So we've taken another small step towards making good predictions. Now we build another tree to predict the new residuals. And add it to the chain of trees that we have already created. And we keep making trees until we reach the maximum specified or adding additional trees does not significantly reduce the size of the residuals.

Bam. Then, when we get some new measurements, we can predict weight by starting with the initial prediction, then adding the scaled value from the first tree, and the second tree, and the third tree, et cetera, et cetera, et cetera. And once the math is all done, we are left with the predicted weight.

In this case, we predicted that this person weighed 70 kg. Triple bam. In summary, when gradient boost is used for regression, we start with a leaf that is the average value of the variable we want to predict. In this case, we wanted to predict weight. Then we add a tree based on the residuals, the difference between the observed values and the predicted values.

And we scale the tree's contribution to the final prediction with a learning rate. Then we add another tree based on the new residuals. And we keep adding trees based on the errors made by the previous tree. That's all there is to it. Bam. Tune in for part two in this series when we dive deep into the math behind the gradient boost algorithm for regression, walking through it step by step, and proving that it really is this simple.

Hooray! We've made it to the end of another exciting StatQuest. If you like this StatQuest and want to see more, please subscribe. And if you want to support StatQuest, consider buying one of my original songs, or buying a StatQuest t-shirt or hoodie. The links are in the description below.

All right. Until next time, quest on.
