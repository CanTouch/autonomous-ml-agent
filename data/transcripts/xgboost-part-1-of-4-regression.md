---
title: "XGBoost Part 1 (of 4): Regression"
url: "https://www.youtube.com/watch?v=OtD8wVaFm6E"
date: "2019-12-16"
video_id: "OtD8wVaFm6E"
uploader: "StatQuest with Josh Starmer"
language: "en"
---

# XGBoost Part 1 (of 4): Regression

XG boost, it's extreme and it's gradient boost. StatQuest Hello, I'm Josh Starmer and welcome to StatQuest. Today we're going to talk about XG boost part one. We're going to talk about XG boost trees and how they're used for regression. Note, this StatQuest assumes that you are already familiar with at least the main ideas of how gradient boost does regression.

And you should be familiar with at least the main ideas behind regularization. If not, check out the quests. The links are in the description below. XG boost is extreme and that means it's a big machine learning algorithm with lots of parts. The good news is that each part is pretty simple and easy to understand and we'll go through them one step at a time.

Actually, I'm assuming that you are already familiar with gradient boost and regularization. So we'll start by learning about XG boost's unique regression trees. Because this is a big topic, we'll spend three whole StatQuests on it. In this StatQuest, part one, we'll build our intuition about how XG boost does regression with its unique trees.

In part two, we'll build our intuition about how XG boost does classification. And in part three, we'll dive into the mathematical details and show you how regression and classification are related and why creating unique trees makes so much sense. Note, XG boost was designed to be used with large, complicated data sets.

However, to keep the examples from getting out of hand, we'll use this super simple training data. On the x-axis, we have different drug dosages. And on the y-axis, we've measured drug effectiveness. These two observations have relatively large positive values for drug effectiveness, and that means that the drug was helpful.

These two observations have relatively large negative values for drug effectiveness, and that means that the drug did more harm than good. The very first step in fitting XGBoost to the training data is to make an initial prediction. This prediction can be anything, but by default, it is 0.5, regardless of whether you're using XGBoost for regression or classification.

The prediction, 0.5, corresponds to this thick, black, horizontal line. And the residuals, the differences between the observed and predicted values, show us how good the initial prediction is. Now, just like unextreme gradient boost, XGBoost fits a regression tree to the residuals. However, unlike unextreme gradient boost, which typically uses regular, off-the-shelf regression trees, XGBoost uses a unique regression tree that I call an XGBoost tree.

So, let's talk about how to build an XGBoost tree for regression. Note, there are many ways to build XGBoost trees. This video focuses on the most common way to build them for regression. Each tree starts out as a single leaf. And all of the residuals go to the leaf.

Now we calculate a quality score or similarity score for the residuals. The similarity score equals the sum of the residuals squared over the number of residuals plus lambda. Note, lambda is a regularization parameter and we'll talk more about that later. For now, let lambda equals zero. Now we plug the four residuals into the numerator.

And since there are four residuals in the leaf, we put a four in the denominator. Note, because we do not square the residuals before we add them together in the numerator, 7.5 and -7.5 cancel each other out. In other words, when we add this residual to this residual, they cancel each other out.

Likewise, 6.5 cancels out most of -10.5, leaving -4 squared in the numerator. Thus, the similarity score for the residuals in the root equals four. So let's put similarity equals four up here so we can keep track of it. Now the question is whether or not we can do a better job clustering similar residuals if we split them into two groups.

To answer this, we first focus on the two observations with the lowest dosages. Their average dosage is 15 and that corresponds to this dotted red line. So, we split the observations into two groups based on whether or not the dosage is less than 15. The observation on the far left is the only one with dosage less than 15.

So, its residual goes to the leaf on the left. All of the other residuals go to the leaf on the right. Now, we calculate the similarity score for the leaf on the left by plugging the one residual into the numerator. And since only one residual went to the leaf on the left, the number of residuals equals one.

And just like before, we set lambda equal to zero. And the similarity score for the leaf on the left equals 110.25. So, let's put similarity equals 110.25 under the leaf so we can keep track of it. And calculate the similarity score for the residuals that go to the leaf on the right.

We plug in the sum of residuals squared into the numerator. And since there are three residuals in the leaf on the right, we plug three into the denominator. And just like before, let's let lambda equal zero. Note, like we saw earlier, because we do not square the residuals before we add them together, 7.5 and -7.5 cancel each other out.

Leaving only one residual, 6.5, in the numerator. Thus, the similarity score for the residuals in the leaf on the right equals 14.08. So, let's similarity equals 14.08 under the leaf so we can keep track of it. Now that we have calculated similarity scores for each node, we see that when the residuals in a node are very different, they cancel each other out and the similarity score is relatively small.

In contrast, when the residuals are similar or there is just one of them, they do not cancel out and the similarity score is relatively large. Now we need to quantify how much better the leaves cluster similar residuals than the root. We do this by calculating the gain of splitting the residuals into two groups.

Gain is equal to the similarity score for the leaf on the left plus the similarity score for the leaf on the right minus the similarity score for the root. Pluging in the numbers gives us 120.33. Small bam. Now that we have calculated the gain for the threshold of dosage less than 15, we can compare it to the gain calculated for other thresholds.

So, we shift the threshold over so that it is the average of the next two observations and build a simple tree that divides the observations using the new threshold, dosage less than 22.5. Now we calculate the similarity scores for the leaves and calculate the gain. The The for dosage less than 22.5 is four.

Since the gain for dosage less than 22.5 is less than the gain for dosage less than 15, dosage less than 15 is better at splitting the residuals into clusters of similar values. Now we shift the threshold over so that it is the average of the last two observations and build a simple tree that divides the observations using the new threshold, dosage less than 30.

Then we calculate the similarity scores for the leaves and the gain. The gain for dosage less than 30 equals 56.33. Again, since the gain for dosage less than 30 is less than the gain for dosage less than 15, dosage less than 15 is better at splitting the observations.

And since we can't shift the threshold over any further to the right, we are done comparing different thresholds. And we will use the threshold that gave us the largest gain, dosage less than 15, for the first branch in the tree. Bam! Now, since there is only one residual in the leaf on the left, we can't split it any further.

However, we can split the three residuals in the leaf on the right. So we start with these two observations and their average dosage is 22.5, which corresponds to this dotted green line. So the first threshold that we try is dosage less than 22.5. Now, just like before, we calculate the similarity scores for the leaves.

Note, we calculated the similarity score for this node when we figured out how to split the root. So, now we calculate the gain. And we get gain equals 28.17 for when the threshold is dosage less than 22.5. Now, we shift the threshold over so that it is the average of the last two observations, calculate the similarity scores for the leaves, and the gain.

And we get gain equals 140.17, which is much larger than 28.17 when the threshold was dosage less than 22.5. So, we will use dosage less than 30 as the threshold for this branch. Note, to keep this example from getting out of hand, I've limited the tree depth to two levels.

And this means we will not split this leaf any further, and we are done building this tree. However, the default is to allow up to six levels. Small bam. Now, we need to talk about how to prune this tree. We prune an XGBoost tree based on its gain values.

We start by picking a number, for example, 130. Oh, no! It's the dreaded terminology alert. XGBoost calls this number gamma. We then calculate the difference between the gain associated with the lowest branch in the tree and the value for gamma. If the difference between the gain and gamma is negative, we will remove the branch.

And if the difference between the gain and gamma is positive, we will not remove the branch. In this case, when we plug in the gain and the value for gamma, 130, we get a positive number. So, we will not remove this branch and we are done pruning. Note, the gain for the root, 120.3, is less than 130, the value for gamma, so the difference will be negative.

However, because we did not remove the first branch, we will not remove the root. In contrast, if we set gamma equal to 150, then we would remove this branch because 140.17 - 150 equals a negative number. So, let's remove this branch. Now, we subtract gamma from the gain for the root.

Since 120.33 - 150 equals a negative number, we will remove the root. And all we would be left with is the original prediction, which is pretty extreme pruning. So, while this wasn't the most nuanced example of how an XGBoost tree is pruned, I hope you get the idea.

Now, let's go back to the original residuals and build a tree just like before, only this time, when we calculate similarity scores, we will set lambda equal to 1. Remember, lambda is a regularization parameter, which means that it is intended to reduce the prediction sensitivity to individual observations.

Now, the similarity score for the root is 3.2, which is 8/10 of what we got when lambda equals 0. When we calculate the similarity score for the leaf on the left, we get 55.12, which is half of what we got when lambda equals 0. And when we calculate the similarity score for the leaf on the right, we get 10.56, which is 3/4 of what we got when lambda equals 0.

So, one thing we see is that when lambda is greater than 0, the similarity scores are smaller. And the amount of decrease is inversely proportional to the number of residuals in the node. In other words, the leaf on the left had only one residual, and it had the largest decrease in similarity score, 50%.

In contrast, the root had all four residuals and the smallest decrease, 20%. Now, when we calculate the gain, we get 66, which is a lot less than 120.33, the value we got when lambda equals 0. Similarly, when lambda equals 1, the gain for the next branch is smaller than before.

Now, just for comparison, these were the gain values when lambda equals 0. When we first talked about pruning trees, we set gamma equal to 130. And because for the lowest branch in the first tree, gain minus gamma equal to positive number, so we did not prune it all.

Now, with lambda equals 1, the values for gain are both less than 130. So, we would prune the whole tree away. So, when lambda is greater than zero, it is easier to prune leaves because the values for gain are smaller. Note, before we move on, I want to illustrate one last feature of lambda.

For this example, imagine we split this node into two leaves. Now, let's calculate the similarity scores with lambda equal to 1. For the branch, we get 65.3. For the left leaf, we get 21.12. And for the right leaf, we get 28.12. That means the gain is -16.06. Now, when we decide if we should prune this branch, we plug in the gain and we plug in a value for gamma.

Note, if we set gamma equal to zero, then we will get a negative number. And we will prune this branch even though gamma equals zero. In other words, setting gamma equal to zero does not turn off pruning. Dang. On the other hand, by setting lambda equal to 1, lambda did what it was supposed to do. It prevented overfitting the training data.

Awesome. For now, regardless of lambda and gamma, let's assume that this is the tree we are working with and determine the output values for the leaves. The output value equals the sum of the residuals divided by the number of residuals plus lambda. Note, the output value equation is like the similarity score, except we do not square the sum of the residuals.

So, for this leaf, we plug in the residual, -10.5, the number of residuals in the leaf, one, and the value for the regularization parameter, lambda. If lambda equals zero, then there is no regularization, and the output value equals -10.5. On the other hand, if lambda equals one, the output value equals -5.25.

In other words, when lambda is greater than zero, then it will reduce the amount that this individual observation adds to the overall prediction. Thus, lambda, the regularization parameter, will reduce the prediction sensitivity to this individual observation. For now, we'll keep things simple and let lambda equal zero, because this is the default value, and put -10.5 under the leaf, so we will remember it.

Now, let's calculate the output value for this leaf. When lambda equals zero, the output value is seven. In other words, when lambda equals zero, the output value for a leaf is simply the average of the residuals in that leaf. So, we'll put the output value under the leaf so we will remember it.

Lastly, when lambda equals zero, the output value for this leaf is -7.5. Now, at long last, the first tree is complete. Double bam! Since we have built our first tree, we can make new predictions. And just like on extreme gradient boost, XG boost makes new predictions by starting with the initial prediction and adding the output of the tree scaled by a learning rate.

Oh, no! It's another dreaded terminology alert. XG boost calls the learning rate eta, and the default value is 0.3. So, that's what we'll use. Thus, the new predicted value for this observation with dosage equal to 10 is the original prediction 0.5 plus the learning rate eta 0.3 times the output value -10.5.

And that gives us -2.65. So, if the original prediction was 0.5, then this was the original residual. The new prediction is -2.65. And we see that the new residual is smaller than before. So, we've taken a small step in the right direction. Similarly, the new prediction for this observation with dosage equal 20, is beep beep.

2.6. And the new residual is smaller than before. So, we've taken another small step in the right direction. Likewise, the new predictions for the remaining observations have smaller residuals than before, suggesting each small step was in the right direction. Bam! Now, we build another tree based on the new residuals and make new predictions that give us even smaller residuals.

And then build another tree based on the newest residuals. And we keep building trees until the residuals are super small or we have reached the maximum number. Triple bam! In summary, when building XGBoost trees for regression, we calculate similarity scores and gain to determine how to split the data.

And we prune the tree by calculating the differences between gain values and a user-defined tree complexity parameter, gamma. If the difference is positive, then we do not prune. If it's negative, then we prune. For example, if we subtract gamma from this gain and get a negative value, we will prune. Otherwise, we're done.

If we prune, then we will subtract gamma from the next gain value and work our way up the tree. Then, we calculate the output values for the remaining leaves. And lastly, lambda is a regularization parameter, and when lambda is greater than zero, it results in more pruning by shrinking the similarity scores.

And it results in smaller output values for the leaves. Bam. Tune in next time for XGBoost part two, when we give an overview of how XGBoost trees are built for classification. It's going to be totally awesome. Hooray! We've made it to the end of another exciting StatQuest. If you like this StatQuest and want to see more, please subscribe. And if you want to support StatQuest, consider contributing to my Patreon campaign, becoming a channel member, buying one or two of my

original songs, or a t-shirt, or a hoodie, or just donate. The links are in the description below. All right. Until next time, quest on.
