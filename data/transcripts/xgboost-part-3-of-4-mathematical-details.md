---
title: "XGBoost Part 3 (of 4): Mathematical Details"
url: "https://www.youtube.com/watch?v=ZVFeW798-2I"
date: "2020-02-10"
video_id: "ZVFeW798-2I"
uploader: "StatQuest with Josh Starmer"
language: "en"
---

# XGBoost Part 3 (of 4): Mathematical Details

XG Boost math details, there's a lot of them. Watch out. StatQuest Hello, I'm Josh Starmer and welcome to StatQuest. Today, we're going to talk about XG Boost part three, mathematical details. This StatQuest assumes that you already have a general idea of how XG Boost builds trees. If not, check out the quests. The links are in the description below.

This StatQuest also assumes that you know the details of how gradient boost works. If not, check out the quests. Lastly, it assumes that you are familiar with ridge regression. If not, the link is in the description below. In XG Boost part one, we saw how XG Boost builds XG Boost trees for regression.

And in XG Boost part two, we saw how XG Boost builds XG Boost trees for classification. In both cases, we built the trees using similarity scores and then calculated the output values for the leaves. Now, we will derive the equations for the similarity scores and the output values and show you how the only difference between regression and classification is the loss function.

To keep the examples manageable, we'll start with a simple training data set for regression and this simple training data set for classification. For regression, we are using drug dosage on the x-axis to predict drug effectiveness on the y-axis. For classification, we are using drug dosage on the x-axis to predict the probability the drug will be effective.

For both regression and classification, we already know that XG Boost starts with an initial prediction that is usually 0.5. And in both cases, we can represent this prediction with a thick black line at 0.5. And the residuals, the differences between the observed and predicted values, show us how good the initial prediction is.

Just like in regular unextreme gradient boost, we can quantify how good the prediction is with a loss function. In gradient boost part two, regression details, we learned how to use this loss function, 1/2 * the squared residual for regression. To review, Y sub I stands for the Y axis value from one of the observed values, Y sub 1, Y sub 2, and Y sub 3.

And P sub I stands for a prediction, P sub 1, P sub 2, and P sub 3, that corresponds to one of the observations, Y sub 1, Y sub 2, and Y sub 3. For example, if we applied the loss function to the initial prediction, then we would add one term for each observation, so N equals 3.

The first term in the summation corresponds to the first observation, Y sub 1. The second term corresponds to the second observation, Y sub 2. And the third term corresponds to the third observation, Y sub 3. So, we just plug in the numbers and do the math and get 104.4.

Later, we can apply the loss function to new predictions and compare the results to this one to determine if our predictions are improving or not. Note, if we had n observations, then we would add up n terms. No big deal. In Gradient Boost part 4, Classification Details, we learned how to use this loss function, the negative log likelihood for classification.

And just like before, y sub i refers to a y axis value for one of the observed values, which is either 0 or 1. And p sub i refers to a predicted value between and including 0 and 1. Note, if you want more details and examples using this loss function, check out the StatQuest Gradient Boost part 4, Classification Details.

Now that we have one loss function for regression and another loss function for classification, XGBoost uses those loss functions to build trees by minimizing this equation. Note, the equation in the original manuscript for XGBoost contains an extra term that I'm omitting. This term, gamma * t, where t is the number of terminal nodes or leaves in a tree, and gamma is a user-definable penalty, is meant to encourage pruning.

I say that it encourages pruning because, as we saw in XGBoost part 1, XGBoost can prune even when gamma equals 0. I'm omitting this term because, as we saw in parts 1 and 2, pruning takes place after the full tree is built, and it plays no role in deriving the optimal output values or similarity scores.

So, let's talk about this equation. The first part is the loss function, which we just talked about. And the second part consists of a regularization term. The goal is to find an output value for the leaf that minimizes the whole equation. And in a way that is very similar to ridge regression, we square the output value from the new tree and scale it with lambda.

Later on, I will show you that, just like ridge regression, if lambda is greater than zero, then we will shrink the output value. The 1/2 just makes the math easier. Note, because we are optimizing the output value from the first tree, we can replace the prediction piece of I with the initial prediction P of zero plus the output value from the new tree.

Now that we understand all of the terms in this equation, let's use it to build the first tree. We start by putting all of the residuals into a single leaf. And now we need to find an output value for this leaf that will minimize this equation. But before we dive into the math, let's simplify things by setting lambda equal to zero.

And that means removing the regularization term. Okay, now let's plug in different output values for the leaf and see what happens. For example, if we set the output value equal to zero, then we are left with the loss function for the initial prediction 0.5. Note, we already calculated the loss function for the initial prediction when we demonstrated the regression loss function, and we got 104.4.

So, let's move the equation up here and plot the result on this graph. The x-axis on this graph represents different values for the output value. And the y-axis represents the sum of the loss functions for each observed value. Now let's see what happens if we set the output value equal to -1.

When the output value for the leaf is -1, then the new prediction is 0.5 + -1, which equals -0.5. And -0.5 corresponds to this new thick black line. And that shrinks the residual for y sub 1, but it makes the residuals for both y sub 2 and y sub 3 larger.

When we do the math, we get 109.4. Now we plot the point on the graph, and we see that -1 is a worse choice for the output value than zero, because it has a larger total loss. In contrast, if we set the output value to positive one, then the new prediction is 0.5 + 1, which equals 1.5.

And that makes the residual for y sub 1 larger, but the residuals for y sub 2 and y sub 3 are smaller. Now when we do the math, we get 102.4. And we see that we have the lowest total so far. And thus, positive one is the best output value we have picked so far.

Note, we can keep plugging in numbers for the output value to see what we get, or we can just plot the function as a curve. The curve shows us that when lambda is zero, then the optimal output value at the bottom of the parabola where the derivative is zero.

Now, let's see what happens when we increase lambda to four. When lambda equals four, the lowest point in the parabola shifts closer to zero. And if we increase lambda to 40, then the lowest point in the parabola shifts even closer to zero. In other words, the more emphasis we give the regularization penalty by increasing lambda, the optimal output value gets closer to zero.

And this is exactly what regularization is supposed to do. So, that's super cool. Bam! Now, one last thing before we solve for the optimal output value. You may remember that when regular unextreme gradient boost found the optimal output value for a leaf, it solved an equation very similar to the first part without regularization.

Unextreme gradient boost used two techniques to solve this equation. One for regression, because the math was easy, and a different one for classification, because the math was not easy. Specifically, for classification, unextreme gradient boost used second-order Taylor approximation to simplify the math when solving for the optimal output value.

In contrast, XGBoost uses a second-order Taylor approximation for both regression and classification. Unfortunately, explaining Taylor series approximations is out of the scope of this StatQuest. So, you'll just have to take my word for it that the loss function that includes the output value can be approximated by this mess of sums and derivatives.

The genius of a Taylor approximation is that it's made of relatively simple parts. This part is just the loss function for the previous prediction. This is the first derivative of that loss function. And this is the second derivative of that loss function. Note, since the derivative of a function is related to something called a gradient, XGBoost uses G to represent the derivative of the loss function.

And since the second derivative of a function is related to something called a Hessian, XGBoost uses H to represent the second derivative of the loss function. Now, let's expand the summation. Beep beep beep beep beep. Add the regularization term. And plug in the second-order Taylor approximation for each loss function.

Beep beep beep beep beep. Before we move on, let's remember that we want to find an output value that minimizes the loss function plus the regularization. And that all we have done so far is approximate the equation we want to minimize with a second-order Taylor polynomial. Now, it's worth noting that these terms do not contain the output value.

And that means they have no effect on the optimal output value. So, we can omit them from the optimization. Now, all that remains are terms associated with the output value. So, let's combine all of the unsquared output value terms into a single term. And combine all of the squared output value terms into a single term.

And move the formula to give us some space to work. Now, let's do what we usually do when we want a value that minimizes a function. One, take the derivative with respect to the output value. Two, set the derivative equal to zero. And three, solve for the output value.

The derivative of the first term with respect to the output value is just the sum of the G's. When we take the derivative of the second term with respect to the output value, the exponent two comes down and cancels out the one half, leaving us with the sum of the H's and lambda times the output value.

Now, we set the derivative equal to zero and solve for the output value. So, we subtract the sum of the G's from both sides and divide both sides by the sum of the H's and lambda. Hooray! We have finally solved for the optimal output value for the leaf.

Now, we need to plug in the gradients, the G's, and the Hessians, the H's, for the loss function. So, let's move the equation out of the way so we have some room. If we're using XGBoost for regression, then this is the most commonly used loss function. Shameless self-promotion.

Just to remind you, this is the exact same loss function that we described in detail in gradient boost part two, regression details. So, if the next few steps move too quickly, just check out the quest. The link is in the description below. The first derivative, aka the gradient, g sub i, with respect to the predicted value, p sub i, is -1 times the difference between the observed value Y sub I and the predicted value P sub I.

In other words, G sub I is the negative residual. That means we plug in the negative residual for each G sub I in the numerator. Note, this negative sign cancels out all of these negative signs. So, the whole numerator is just the sum of the residuals. Now, we need to figure out what the H's are in the denominator.

The second derivative, aka the Hessian, H sub I, with respect to the predicted value, P sub I, is the number one. So, that means we replace all in H's in the denominator with the number one. In other words, the denominator is the number of residuals plus lambda. So, when we are using XGBoost for regression, this is the specific formula for the output value for a leaf.

To summarize what we've done so far, we started out with this data, then we made an initial prediction, 0.5, then we put all of the residuals in this leaf, then we asked ourselves what the output value of this leaf should be given a loss function and regularization. We then plotted the equation as a function of the output value and solved for the lowest point where the derivative is zero.

And this is what we got. The equation for the output value gives us the x-axis coordinate for the lowest point in the parabola. Bam! Now, if we are using XGBoost for classification, then this, the negative log likelihood, is the most commonly used loss function. Shameless self-promotion. This is the exact same loss function that we worked with in gradient boost part four, classification details.

In that StatQuest, we spent a long time deriving the first and second derivative of this equation. Calculating the derivatives took a long time because the output values are in terms of the log odds. So, we converted the probabilities to log odds one step at a time, rather than skipping the fun parts like we are now.

Then, we took the derivatives without skipping the fun parts like we're doing here. And lastly, we converted the log odds back to probabilities without skipping any steps in the math. Note, if you feel like you just missed out on a lot of fun stuff, fear not. The link to gradient boost part four, classification details, is in the description below.

Now that we have the first derivative of the loss function, aka the gradient g sub i, and the second derivative of the loss function, aka the Hessian h sub i, we can plug them into the equation for the optimal output value. Just like for regression, g sub i is the negative residual.

And we know that this negative sign will cancel out this negative sign in the numerator for the output value. So, we can replace the numerator for the output value with the sum of the residuals. In the denominator, we can just replace all of the h sub i's with the sum of p sub i * 1 - p sub i.

Note, in the denominator, we're using previous probability to specify the previously predicted probability rather than the previously predicted log odds. So, when we are using XGBoost for classification, this is the specific formula for the output value for a leaf. Bam! Now, regardless of whether we are using XGBoost for regression or classification, we can calculate the optimal output value for this leaf.

And we do it by plugging derivatives of the loss functions into the equation for the output value. Bam! Now, we need to derive the equations for the similarity score so we can grow the tree. However, before we do that, remember that we derived the equation for the output value by minimizing the sum of the loss functions plus the regularization.

And let's also remember that depending on the loss function, optimizing this part can be hard, so we approximated it with a second-order Taylor polynomial. So, we expanded the summation, added the regularization term, and swapped in the second-order Taylor approximation of the loss function. Then removed the constant terms, and lastly, did a little algebra to simplify everything.

Now, because we removed constants when deriving this equation, it's not equal to what we started with. However, if we plotted both equations on a graph, we'd see that the same x-axis coordinate represented by the optimal value tells us the location of the lowest points in both parabolas. I mention this because XGBoost uses the simplified equation to determine the similarity score.

So, the first thing XGBoost does is multiply everything by -1. And that makes each term negative, and it flips the parabola over the horizontal line y = 0. Now, the optimal output value represents the x-axis coordinate for the highest point on the parabola. And this y-axis coordinate for the highest point on the parabola is the similarity score.

At least, it's the similarity score described in the original XGBoost manuscript. However, the similarity score used in the implementations is actually two times that number. The reason for this difference will become clear once we do the algebra. So, let's do the algebra to convert this into the similarity scores we saw in XGBoost parts one and two.

First, let's plug in the solution for the output value. Now, multiply together the sums of the gradients, G's, on the left. Note, these negative signs cancel out, and we get the square of the sum. Now, we square the term on the right, and let this sum cancel out this square.

Now, we add these two terms together, and we end up with this fraction. This is the equation for the similarity score as described in the original XGBoost manuscript. However, in the XGBoost implementations, this 1/2 is omitted because the similarity score is only a relative measure. And as long as every similarity score is scaled the same amount, the results of the comparisons will be the same.

This is an example of how extreme extreme gradient boost is. It will do anything to reduce the amount of computation. Now, if we're using XGBoost for regression and we're using this loss function, we plug the first derivative, g sub i, into the numerator. And since g sub i is the negative residual, the numerator is simply the sum of the residuals squared.

Now, we plug the second derivative, h sub i, into the denominator. And since h sub i equals 1, the denominator is just the number of residuals plus lambda. Thus, this equation is the similarity score that we use for regression. Double bam! Now, we need to derive the similarity score for classification.

And that just means plugging in the first derivative for the loss function, g sub i, and the second derivative, h sub i. Again, since g sub i is the negative residual, the numerator is simply the sum of the residuals squared. And since h sub i is the previously predicted probability times 1 minus the previously predicted probability, then the denominator is just the sum of the h sub i's plus lambda.

Thus, this equation is the similarity score that we use for classification. Triple bam! Now for one little annoying detail. In part two of this series, we talked about cover. Cover is related to the minimum number of residuals in a leaf. And we said that cover was the denominator of the similarity score minus lambda.

In other words, cover is the sum of the Hessians, the H sub i's. For regression, the Hessian, aka the second derivative of the loss function, is one. And since there is one Hessian per residual in a leaf, cover for regression is simply the number of residuals in a leaf.

For classification, the Hessian is P * 1 - P. So, cover is equal to the sum of the previously predicted probability * 1 - the previously predicted probability. Small bam! In summary, XGBoost builds trees by finding the output value that minimizes this equation. The equation consists of a loss function and a regularization term that is just like ridge regression.

We then solve for the optimal output value. And once we have the output value, we plug it into the simplified equation to get the similarity score. We then configure the output value and similarity score equations for regression or classification by plugging in the first derivative, G sub i, and the second derivative, H sub i, of the loss function.

Bam! Hooray! We've made it to the end of another exciting StatQuest. If you like this StatQuest and want to see more, please subscribe. And if you want to support StatQuest, consider contributing to my Patreon campaign, becoming a channel member, buying one or two of my original songs, or a t-shirt, or a hoodie, or just donate. The links are in the description below.

All right. Until next time, quest on.
