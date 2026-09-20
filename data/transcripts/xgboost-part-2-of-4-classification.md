---
title: "XGBoost Part 2 (of 4): Classification"
url: "https://www.youtube.com/watch?v=8b1JEDvenQU"
date: "2020-01-13"
video_id: "8b1JEDvenQU"
uploader: "StatQuest with Josh Starmer"
language: "en"
---

# XGBoost Part 2 (of 4): Classification

Classification. It's not a vacation. It's not a sensation. But it's cool. StatQuest. Hello, I'm Josh Starmer and welcome to StatQuest. Today we're going to talk about XGBoost part two, XGBoost trees for classification. Note, this StatQuest assumes that you are already familiar with the main ideas of how XGBoost does regression and at least the main ideas of how gradient boost is used for classification.

If not, check out the quests. The links are in the description below. XGBoost is extreme. And that means it's a big machine learning algorithm with lots of parts. The good news is that each part is pretty simple and easy to understand. And we'll go through them one step at a time.

In part one in this series, we provided an overview of how XGBoost trees are built for regression. In this video, part two, we'll give an overview of how XGBoost trees are built for classification. And in part three, we'll dive into the mathematical details to show you how regression and classification are related and why creating unique trees makes so much sense.

Note, XGBoost was designed to be used with large, complicated data sets. However, to keep the examples from getting out of hand, we will use this super simple training data consisting of four different drug dosages. The green dots indicate the drug was effective. And the red dots indicate that the drug was not effective.

The very first step in fitting XGBoost to training data is to make an initial prediction. This prediction can be anything. For example, the probability of observing an effective dosage in the training data, but by default, it is 0.5, regardless of whether you are using XGBoost for regression or classification.

In other words, regardless of the dosage, the default prediction is that there is a 50% chance the drug is effective. We can illustrate the initial prediction by adding a Y axis to our graph to represent the probability that the drug is effective and drawing a thick black line at 0.5 to represent a 50% chance that the drug is effective.

Since these two green dots represent effective dosages, we will move them to the top of the graph, where the probability that the drug is effective is one. These two red dots represent ineffective dosages, so we will leave them at the bottom of the graph, where the probability that the drug is effective is zero.

The residuals, the differences between the observed and predicted values, show us how good the initial prediction is. Now, just like we did for regression, we fit an XGBoost tree to the residuals. However, since we are using XGBoost for classification, we have a new formula for the similarity scores.

Note, even though the numerator looks fancy, it's just the sum of the residuals squared. In other words, the numerator for classification is the same as the numerator for regression. And just like for regression, the denominator contains lambda, the regularization parameter. However, the rest of the denominator is different.

The good news is that we already saw something just like this in regular unextreme gradient boost. It's just the sum for each observation of the previously predicted probability * 1 - the previously predicted probability. Note, although this formula is different from what XGBoost uses for regression, it is very closely related, and we will show you why in part three when we get into the nitty-gritty details.

Now, let's build a tree. Just like for regression, each tree starts out as a single leaf, and all of the residuals go to the leaf. Now, we need to calculate a similarity score for the leaf. And that means we plug all four residuals into the numerator. Note, because we do not square the residuals before we add them together, they will cancel each other out.

And we will end up with zero in the numerator, and that makes the similarity score equal to zero. And that's a little bit of a bummer since it doesn't give us a chance to talk about the denominator, which is the interesting part. However, don't freak out. We'll get to it soon.

For now, let's just put similarity equals zero up here so we can keep track of it. Now, we need to decide if we can do a better job clustering similar residuals if we split them into two groups. We'll start with this threshold, dosage less than 15. Note, we chose the threshold dosage less than 15 because 15 is the average value between the last two observations.

Thus, the three residuals with dosages less than 15 go to the leaf on the left and the one residual with dosage greater than 15 goes to the leaf on the right. To calculate the similarity score for the three residuals that ended up in the leaf on the left, we plug the three residuals into the numerator.

And since we are building the first tree, the previous probability refers to the prediction from the initial leaf. So, we plug in 0.5 for each residual that ended up in the leaf. Now, just to keep things simple, we'll let lambda equal zero. However, you know from part one that lambda reduces the similarity score, which ultimately makes leaves easier to prune.

Now, notice that these two residuals in the numerator cancel each other out, leaving us with just one residual in the numerator. And when we do the math, we get 0.33. So, let's put similarity equals 0.33 under this leaf so we can keep track of it. The similarity score for the leaf on the right is one when lambda equals zero.

So, let's put similarity equals one under this leaf to keep track of it. Now, we can calculate the gain just like we did when we used XG Boost for regression. We plug in the similarity scores and get 1.33. So, when we split the observations based on the threshold dosage less than 15, gain equals 1.33.

Since I'm such a nice guy, I'm going to tell you that no other threshold gives us a larger gain value. And that means dosage less than 15 will be the first branch in our tree. Now, we can focus on splitting these residuals into two leaves. Note, we can tell just by looking at the data that this threshold dosage less than five has a higher gain than this threshold dosage less than 10.

This is because when the threshold is dosage less than 10, these two residuals will cancel each other out. And the similarity score for this leaf will be zero. So, when we calculate the gain, we get 0.66. Now, let's compare that to the gain we get when the threshold is dosage less than five.

These are the similarity scores and when we plug them into the equation for the gain, we get 2.66. And since 2.66 is greater than 0.66, we will use dosage less than five as the threshold for this branch. Now, since I'm limiting the trees to two levels, we will not split this leaf any further and we are done building this tree.

Bam! Note, we stop growing this tree because we limited the number of levels to two. However, XGBoost also has a threshold for the minimum number of residuals in each leaf. Warning, it's time for some tedious detail and terminology. The minimum number of residuals in each leaf is determined by calculating something called cover.

Cover is defined as the denominator of the similarity score minus lambda. In other words, when we are using XGBoost for classification, cover is equal to the sum of the previous probability times 1 minus the previous probability for each residual that's in the leaf. In contrast, when XGBoost is used for regression and we are using this formula for the similarity score, then cover is equal to the number of residuals in a leaf.

By default, the minimum value for cover is one. Thus, by default, when we use XGBoost for regression, we can have as few as one residual per leaf. In other words, when we use XGBoost for regression and use the default minimum value for cover, cover has no effect on how we grow the tree.

In contrast, things are way more complicated when we use XGBoost for classification because cover depends on the previously predicted probability of each residual in a leaf. For example, the cover for this leaf is the previously predicted probability for this observation, which was 0.5 * (1 - the previously predicted probability) which is 0.25.

And since the default value for the minimum cover is 1, XGBoost would not allow this leaf. Likewise, the cover for this leaf is equal to 0.5. So, by default, XGBoost would not allow this leaf, either. Since these leaves are not allowed, let's remove them and go back to this leaf.

Because the previously predicted probability is the same for all three of these residuals, cover is just three times the cover for one of the residuals, and that means cover = 0.75. So, XGBoost would not allow this leaf, either. Ultimately, if we use the default minimum value for cover, 1, then we would be left with the root, and XGBoost requires trees to be larger than just the root.

So, in order to prevent this from being the worst example ever, let's set the minimum value for cover equal to zero. And that means setting the min child weight parameter equal to zero. Small bam. Now we can talk about how to prune the tree. Just like we did in part one, we prune by calculating the difference between the gain associated with the lowest branch and a number we pick for gamma.

For example, if we plugged in the gain and set gamma equal to two, then we would not prune because the difference is a positive number. In contrast, if we set gamma equal to 3, then we would prune because the difference is a negative number. And we would also prune this branch because 1.33 - 3 equals a negative number.

And all we would be left with is the original prediction. Small bam. Now, going back to the original tree, remember from part one that lambda, the regularization parameter, reduces the similarity scores, and that lower similarity scores result in lower values for gain. For example, if we set lambda equal to 1, then we would get these lower values for gain.

And that means a lower value for gamma will result in a negative difference and cause us to prune branches. In other words, values for lambda greater than zero reduce the sensitivity of the tree to individual observations by pruning and combining them with other observations. Bam. For now, regardless of lambda and gamma, let's assume that this is the tree we are working with and determine the output values for the leaves.

For classification, the output value for a leaf is the sum of the residuals divided by the sum of the previous probability * 1 - the previous probability for each residual in the leaf plus lambda. Note, with the exception of lambda, the regularization parameter, this is the same formula we used for unextreme gradient boost.

So, for this leaf, we plug in the residual -0.5 and the previously predicted probability and the value for the regularization parameter, lambda. If lambda equals zero, then there is no regularization and the output value equals -2. On the other hand, if lambda equals one, then the output value equals -0.4, which is closer to zero than -2 when lambda equals zero.

In other words, when lambda is greater than zero, then it reduces the amount that this single observation adds to the new prediction. Thus, lambda, the regularization parameter, reduces the prediction sensitivity to isolated observations. For now, we'll let lambda equal zero because this is the default value and put -2 under the leaf so we will remember it.

Similarly, when lambda equals zero, the output value for this leaf is two. Note, if lambda equals one, then we get 0.67, which is closer to zero, but the effect of lambda is smaller this time because there are two observations in this leaf. But like I said, we'll let lambda equal zero since that is the default value and put two under the leaf so we will remember it.

Lastly, when lambda equals zero, the output value for this leaf is -2. Hooray! The first tree is complete. Double bam! Now that we have built the first tree, we can make new predictions. Just like other boosting methods, XGBoost for classification makes new predictions by starting with the initial prediction.

However, just like with unextreme gradient boost for classification, we need to convert this probability to a log odds value. So, since this is the formula that converts probabilities to odds, we can get a formula that converts probabilities to the log odds by taking the log of both sides.

Note, if these equations are freaking you out, just watch the StatQuest on odds and log odds. The link is in the description below. In this case, we plug in P = 0.5, do the math, and we see that when P = 0.5, the log of the odds equals 0.

So, let's put that under the initial prediction so we don't forget. Now, just like unextreme gradient boost for classification, we add the log odds of the initial prediction to the output of the tree scaled by a learning rate. XGBoost calls the learning rate eta, and the default value is 0.3. So, that's what we'll use.

Thus, the new predicted value for this observation with dosage equal 2 is the log of the odds for the original prediction, 0, plus the learning rate, 0.3, times the output value, -2. And that gives us a log of the odds value equal to -0.6. To convert a log of the odds value into a probability, we plug it into the logistic function.

Note, if the logistic function makes you feel a little uncomfortable, check out the StatQuest logistic regression details part two, fitting a line with maximum likelihood. Assuming we're cool with this equation, let's plug in the log of the odds. Do the math, and the new predicted probability is 0.35.

Remember, the original prediction was 0.5, and this was the original residual. Now, the new predicted probability is 0.35, and the new residual is smaller than before, so we've taken a small step in the right direction. Hooray! Note, you may be wondering why we even bothered adding the log of the odds of the initial prediction since it is zero.

This is always the case if you use the default value, 0.5, for the initial prediction. However, you can change the initial prediction to any probability, and any value other than 0.5 will give you something more interesting to add. For example, if 75% of the observations in the training data said that the drug was effective, we might set the initial prediction to 0.75, and now the initial log of the odds equals 1.1.

So, we would plug 1.1 into the equation instead of zero. But since the default initial prediction is 0.5, we will use zero for the initial log of the odds in the remaining examples. Now, let's make a new prediction for this observation with dosage equal to eight. We start with the original log of the odds prediction, zero, plus 0.3 times the output value, two, and the predicted log of the odds equals 0.6.

Now, we convert the log of the odds to a probability, and we get 0.65. And this residual is smaller than before, so we've taken another small step in the right direction. Likewise, the new predictions for the remaining observations have smaller residuals than before. Bam! Now that we have new residuals, we can build a second tree that is fit to the new residuals.

Note, when we build the second tree, calculating the similarity scores is a little more interesting because the previous probabilities are no longer the same for all of the observations. For example, since all of the residuals start in the root of the tree, we would plug in the previously predicted probabilities for each observation into the denominator, and this time they are not all the same.

Similarly, if we had to calculate an output value for the root, the denominator would also contain a mixture of previously predicted probabilities. Small bam. Now that we have a new tree, we add it to all of the previous predictions, and make new predictions that give us even smaller residuals.

Then we build another tree based on the new residuals, and we keep building trees until the residuals are super small or we have reached the maximum number of trees. Triple bam! In summary, when building XGBoost trees for classification, we calculate similarity scores and gain to determine how to split the data, and we prune the tree by calculating the difference between gain values and a user-defined tree complexity parameter, gamma.

For example, if we subtract gamma from this gain and get a negative value, we will prune. Otherwise, we're done. If we prune, then we will subtract gamma from the next gain value, etc., etc., etc. Then we calculate the output values for the leaves. And lastly, lambda is a regularization parameter, and when lambda is greater than zero, it results in more pruning by shrinking the similarity scores and smaller output values for the leaves.

Oh, and I almost forgot. When using XGBoost for classification, we have to be aware that the minimum number of residuals in a leaf is related to a metric called cover, which is the denominator of the similarity score minus lambda. Tune in next time for XGBoost part three when we dive deep into the nitty-gritty details of the math that ties XGBoost trees for regression and classification into one elegant equation.

Hooray! We've made it to the end of another exciting StatQuest. If you like this StatQuest and want to see more, please subscribe. And if you want to support Stat Quest, consider contributing to my Patreon campaign, becoming a channel member, buying one or two of my original songs, or a t-shirt, or a hoodie, or just donate. The links are in the description below.

All right, until next time, quest on.
