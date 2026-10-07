---
title: "Gradient Boost Part 4 (of 4): Classification Details"
url: "https://www.youtube.com/watch?v=StWY5QWMXCw"
date: "2019-04-22"
video_id: "StWY5QWMXCw"
uploader: "StatQuest with Josh Starmer"
language: "en"
---

# Gradient Boost Part 4 (of 4): Classification Details

Gradient boost for classification seems scary, but it's not. StatQuest Hello, I'm Josh Starmer and welcome to StatQuest. Today, we're going to do gradient boost part four. We're going to talk about how gradient boost is used for classification and we're going to dive deep into the details. Note, this StatQuest assumes you've already watched the first three parts in this series. If not, check out the quests.

Also, it's important that you have a pretty good understanding of the roles that the log odds and the log likelihood play in logistic regression. So, if you haven't already, check out these quests. In this StatQuest, we will walk through the original gradient boost algorithm for classification step-by-step. Just like in part two of this series, we will use an incredibly small training set for the examples.

The small size will help us focus on the algorithm's details, but it will mean using stumps instead of trees. However, by now you know that in practice, gradient boost usually uses trees with between eight and 32 leaves. Now, we'll describe our training data set. We have whether or not three people like popcorn, their age, their favorite color, and whether or not they love the movie Troll 2.

Great. Now that we know all about the training data set, let's go through the algorithm step-by-step. We'll start from the top. From part two in this series, we know that this refers to the training data set. Just to remind you, X sub I refers to a row of measurements that we will use to predict if someone loves Troll 2.

And Y sub I refers to whether or not someone loves Troll 2. Now, we need a differentiable loss function that will work for classification. I think the easiest way to understand the most commonly used loss function for classification is to show how it works on a graph. The Y axis is the probability of loving Troll 2.

The red dot with the probability of loving Troll 2 equal to zero represents the one person that does not Troll 2. And the blue dots with the probability of loving Troll 2 equal to one represent the two people that love Troll 2. In other words, the red and blue dots are the observed values.

And we can draw a dotted line to represent the predicted probability that someone loves Troll 2. In this example, I've set the predicted probability to 0.67. Now, just like we do for logistic regression, we can calculate the log likelihood of the data given the predicted probability. The log likelihood of the observed data given the prediction is this nasty looking summation.

The P's refer to the predicted probability, which is 0.67 in this example. And the Y sub I's refer to the observed values for loves Troll 2. For the two people who love Troll 2, Y sub I equals 1, which means that this term will be zero. Leaving just the log of P.

In contrast, for the one person who does not love Troll 2, Y sub I equals zero, which means that this term will be zero. Leaving just the log of 1 minus P. Now, let's use the summation to calculate the log likelihood of all three observed values. We'll start by calculating the log likelihood for the first person.

Because this person loves Troll 2, Y sub 1 equals 1. Then we plug in 0.67 for the predicted probability, P. 1 minus 1 equals 0. And now we do the multiplication. The log likelihood for the first person, given the predicted probability, is the log of 0.67. Now let's calculate the log likelihood for the second person.

We plug in the observed value, 1, for Y sub 2. And plug in 0.67 for the predicted probability, P. 1 minus 1 equals 0. And now we do the multiplication. And we get the log of 0.67 since the predicted probability was the same. Now let's calculate the log likelihood for the third person.

We plug in the observed value, 0, for Y sub 3 since this person does not love the movie. Plug in 0.67 for the predicted probability, P. 1 minus 0 equals 1. And now we do the multiplication. And we get the log of 1 minus 0.67. Note, the better the prediction, the larger the log likelihood. And this is why, when doing logistic regression, the goal is to maximize the log likelihood.

That means that if we want to use the log likelihood as a loss function, where smaller values represent better fitting models, then we need to multiply the log likelihood by -1. So, we'll put this subtle, but very important, minus sign in front of everything. And since a loss function sometimes only deals with one sample at a time, we can get rid of the summation.

And to make it easier to read, we'll replace Y with observed. Now, we need to transform this equation, the negative log likelihood, so that it is a function of the predicted log odds instead of the predicted probability, P. And we need to simplify it. Since this will require a lot of steps, we'll move the negative log likelihood to the top left-hand corner to give us space to work.

The first thing we do is distribute the minus sign through the equation. Now, we multiply the negative 1 minus observed by the log of 1 minus P. Now, we combine this with this and get this. And since the log of P minus the log of 1 minus P equals the log of P divided by the log of 1 minus P, and that equals the log of P divided by 1 minus P, and that equals the log of the odds.

So, we replace the log of P minus the log of 1 minus P with the log of the odds. In other words, we converted the log of P minus the log of 1 minus P into a function of the log of the odds. Note, the relationship between probability, P, and the log of the odds is derived in the StatQuest on odds and the log of the odds, so check that out if you want more details.

Now, we need to convert the log of 1 minus P into a function of the log of the odds. The log of 1 - P equals the log of 1 e to the log odds divided by 1 + e to the log odds. Note, this relationship between probability P and the log of the odds is derived in the logistic regression StatQuest on estimating parameters with maximum likelihood.

Now we replace 1 with this fraction. Do the subtraction and we get the log of 1 divided by 1 + e to the log odds. Now convert the division into subtraction and since the log of 1 equals 0, we can remove it. And that leaves us with the negative log of 1 + e to the log odds.

Thus, the log of 1 - P, which is a function of the predicted probability P, can be transformed into a function of the predicted log odds. So let's plug that in. Note, this sign changed from negative to positive because we replaced the log of 1 - P with a negative log of 1 + e to the log odds.

Hooray! We converted the negative log likelihood of the data, which is a function of the predicted probability P, into a function of the predicted log odds. Bam! So this will be the loss function. Now we just need to show that it is differentiable. So let's take the derivative of the loss function with respect to the predicted log odds.

The derivative of the first part with respect to the predicted log odds is super easy. It's just the negative observed value. The derivative of the second part is also super easy if you know how to use the chain rule. The derivative of the log of something is one over that something times the derivative of that something.

And this multiplication can be rewritten as a single fraction. Note, earlier we saw that we can substitute the predicted probability P with this fraction. But we can also swap the predicted probability P back in. And that means that the derivative of the loss function can be a function of the predicted log odds or a function of the predicted probability P.

As we will soon see, sometimes it's easier to use the function of the log odds and sometimes it's easier to use the function of the predicted probability P. In summary, the input data is the training data set and this fairly nasty looking thing, which is just a transformation of the negative log likelihood, is the differentiable loss function.

And the derivative can be a function of the predicted log odds or a function of the predicted probability P. Hooray! Now we're ready for step one. Just like when we used gradient boost for regression, we need to come up with the initial prediction. And just like before, we'll use this funky looking equation to find the optimal initial prediction.

Remember, this is just the loss function. The YI refers to the observed values. And that funky symbol, called gamma, refers to a log odds value. In theory, we could go ahead and replace the log odds with gamma, but it's actually easier to see what's going on if we leave the log odds in and remember that it represents gamma.

The summation means that we add up one loss function for each observed value. And the argmin over gamma means we need to find a log odds value that minimizes this sum. The first thing we do is take the derivative of each term with respect to the log odds.

Now, to make the next step super easy, let's replace the log odds with the predicted probability, P, and set the sum of the derivatives equal to zero and solve. Beep boop boop beep boop boop beep boop. Beep boop boop. And we end up with 2 / 3 for the initial predicted probability, P, because two people love Troll 2 and there are three people in the training data set.

Now we can convert the predicted probability into the predicted log odds. So we plug in the predicted probability and solve. Beep boop boop. And the predicted log odds is the log of 2 / 1, which makes sense because two people love Troll 2 and one person does not.

So, given this loss function, the log odds value for gamma that minimizes this sum is the predicted log odds of loving Troll 2 based on the observed yes, no values. Hooray! We've created the initial predicted log odds, f sub zero of x. It equals 0.69. So this is the initial leaf, F sub 0 of X.

Bam! We finished step one. We initialize the model with a constant value, F sub 0 of X equals the log of 2 / 1, which equals 0.69. In other words, we created a leaf that predicts the log odds that someone will love Troll 2, and it equals 0.69.

Now, we can work on step two. Just like when we used gradient boost for regression, this is when we'll build the trees. So, we'll start by setting little M equal to 1 and go from here. In part A, we calculate pseudo residuals with this nasty looking thing. This is just the derivative of the loss function with respect to the predicted log odds.

And we've already calculated this. This big minus sign tells us to multiply the derivative by -1. And that leaves us with this equation for calculating pseudo residuals. Note, as we have seen before, we can replace this term with the predicted probability, P. So, we can think of the pseudo residuals as the observed probability minus the predicted probability.

And the observed minus the predicted results in a pseudo residual. This part says to plug in the most recent predicted log odds. So, we plug in F sub 0 of X, the most recent predicted log odds. Then do the math to convert the predicted log odds into the predicted probability, P.

Now, we can compute the pseudo residuals for each sample, R sub I, M, where I is the sample number and m is the tree that we're building. So, we'll start with r sub 1,1, the residual for the first sample and the first tree. So, we plug in the observed weight for the first sample, and we get 0.33.

We'll keep track of r sub 1,1 by adding it to the data set. Now, we'll calculate the other two residuals. Beep beep beep beep beep. Hooray! We've finished part A of step two by calculating a residual for each sample. Now, we're ready for part B, where we will build a regression tree.

We will build a regression tree using likes popcorn, age, and favorite color to predict the residuals. Here's the new tree. So, we have a regression tree fit to the residuals. Now, we need to create terminal regions, r sub j,m. So, in this example, we'll name this leaf r sub 1,1, and name this leaf r sub 2,1.

Hooray! We've finished part B of step two by fitting a regression tree to the residuals and labeling the leaves. Now, let's do part C. This is when we calculate the output values for the new tree. So, for each leaf in the new tree, we compute an output value, gamma sub j,m.

The output value for each leaf is the value for gamma that minimizes this summation. The x sub i and r sub i,j means that since only the first row of data, x sub 1, goes to leaf r sub 1,1, then only x sub 1 is used to calculate the output value for r sub 1,1.

And since only two samples, x sub 2 and x sub 3, go to leaf r sub 2,1, then only x sub 2 and x sub 3 are used to calculate the output value for r sub 2,1. Let's start by calculating the output value for the leaf on the left, r sub 1,1.

That means that j equals 1, since this is the first leaf, and m equals 1, since this is the first tree. Remember, this is just the loss function. So, we can replace the generic form with the actual loss function that we are using. Note, to keep the length of the formula from getting out of hand, I'm returning to using y sub i to refer to the observed values.

Since only x sub 1 goes to r sub 1,1, we can remove the big sigma and swap the i's with 1's. Now, let's solve for the optimal value for gamma. In theory, we could take the derivative of this function with respect to gamma and then solve for gamma, but that would turn into a huge mess.

So, we will take a different approach than when we used gradient boost for regression. Let's start by moving the equation up here to give us room to work. And even though we want to minimize gamma, let's remember that we are working with the loss function. Since taking the derivative of the loss function with respect to gamma and then solving for gamma is hard, we can approximate the loss function with a second-order Taylor polynomial.

Why this second-order Taylor polynomial is a good approximation is something we can talk about in a future StatQuest. For now, just take my word for it. Now we can take the derivative of this function with respect to gamma. Since gamma is not part of this term, the derivative with respect to gamma is zero, so we can omit it.

The derivative of this with respect to gamma is super easy. We can treat this, the derivative of the loss function with respect to the predicted log odds, as a constant. And the derivative of a constant times gamma is the constant. Similarly, the derivative of this with respect to gamma is super easy.

All this stuff, 1/2 times the second derivative of the loss function with respect to the predicted log odds, can be treated like a constant. And we get this because the square on the gamma comes down and cancels the 1/2. Using the approximation of the loss function made taking the derivative with respect to gamma super easy.

Now let's move it up to give ourselves a little more room. Set it equal to zero and solve for gamma. First, we'll subtract this term from both sides. Beep. Then, we'll divide both sides by this term. Boop. Bam! We solved for gamma. And now, just because I'm into moving equations to the top of the screen, let's move this one up.

Gamma equals -1 times the derivative of the loss function divided by the second derivative of the loss function. Since we have already solved for this, we can just plug it in. And we can replace this with the predicted probability P and the observed value minus the predicted probability P is just the residual.

Now, we need to take the second derivative of the loss function to figure out what goes in the denominator. The second derivative of the loss function equals the derivative of the first derivative of the loss function. So, we can plug in the first derivative of the loss function.

Now, to make taking the derivative a little more obvious, let's rewrite this fraction as multiplication. Now, we need to take the derivative of this with respect to the log odds. The derivative of negative observed is zero. So, we can ignore this part. This part, however, is a little more involved. We'll need to use the product rule.

The product rule says that the derivative of A * B equals the derivative of A * B + A * the derivative of B. So, we start with the derivative of the first part by using the chain rule. And that gives us this derivative. Then, we multiply by the second part.

Then, we add the first part times the derivative of the second part. Bam! This long thing is the second derivative of the loss function. Technically, we could leave this as it is and move on. But, with a little bit of algebra, we can get something way, way easier to work with.

So, let's move this to the top of the screen so that we have room to work. The first thing we do is rewrite this as a fraction. Then, we rewrite this as a fraction. Then, we multiply the top and bottom of the second term by 1 + e to the log odds.

And now we can add these terms together. These two parts in the numerator cancel each other out. And that leaves us with this. Note, I also split the denominator into two terms so that the next steps make more sense. Now we'll multiply the numerator by 1, which seems silly, but is the key to reducing the whole thing into two super simple terms.

By multiplying the numerator by 1, we can easily see how this single term separates into two terms multiplied together. At this point, you may recognize the first term. It converts the predicted log odds to the predicted probability, p. The second term should also remind you of something we have seen earlier in this StatQuest.

Earlier, we saw that the log of 1 - p equals this. And that means that 1 - p equals this. Which means the second term is just 1 - the predicted probability, p. So at long last, we see that the second derivative of the loss function is equal to p * 1 - p.

And that brings us back to gamma. Earlier, we saw that gamma equals the residual divided by the second derivative of the loss function. And now we can replace the second derivative of the loss function with p * 1 - p. Bam! I know it seems like a long time ago, but remember, we were trying to find out the output value for this leaf.

In other words, we were trying to find the value for gamma that, when added to the most recent predicted log odds, minimized the loss function. Then we did a ton of math and discovered that gamma sub 1,1 is the residual divided by P * 1 - P. Now we can plug in the residual and the most recent predicted probability, P, for this sample.

In this case, the predicted probability for this sample is derived from F sub 0 of X, the most recent log odds prediction. Now we just do the math and the output value for leaf R sub 1,1 is 1.5. Now let's calculate the output value for the other leaf, R sub 2,1.

That means we're calculating gamma sub 2,1. Since samples X2 and X3 go to leaf R sub 2,1, then we will need a loss function for X sub 2 and a loss function for X sub 3. Now, just like before, we can approximate the loss function with second-order Taylor polynomials.

Here's the second-order Taylor polynomial approximation of the loss function for sample X sub 2. And here's the second-order Taylor polynomial approximation of the loss function for X sub 3. If we add these two loss functions together, we get this. And we can approximate that sum by adding together the two Taylor polynomials.

We'll start by adding the first terms in the Taylor polynomials. Then add the second terms. And then add the third terms. Note, we can pull these two gammas out of the second terms. And we can pull the one halves and the gamma squareds out of the third terms.

Now let's move everything to the top so we have some space to determine the optimal value for gamma. The first step in finding the optimal value for gamma is to take the derivative of the sum of the two approximate loss functions with respect to gamma. The derivative of this part is zero since gamma is not involved at all.

For the second term, since everything between the square brackets is like a constant with respect to gamma, the derivative is everything between the square brackets. And for the third term, the derivative of this with respect to gamma means the square comes down and cancels out the one half.

And that leaves us with everything between the square brackets times gamma. So this is the derivative of the sum of the approximate loss functions with respect to gamma. Move it to the top so we have some room to work. Set it equal to zero. Now solve for gamma.

First, we subtract this square bracket stuff from both sides. Now we divide both sides by this square bracket stuff. And this is the solution for gamma. Now all we need to do is simplify it. So we move it to the top to give us a little room to work.

In the numerator, we have two separate derivatives of the loss function, one for X2 and one for X3. And since we already know that the derivative of the loss function is this, we can plug it in for x 2 and for x 3. And since e to the log odds divided by 1 + e to the log odds equals p, we can plug in p sub 2, the predicted probability for x sub 2.

And we can plug in p sub 3, the predicted probability for x sub 3. Now we multiply the -1 through the numerator. And that leaves us with the observed minus the predicted probabilities for x sub 2 and x sub 3. In other words, we are left with the sum of the residuals in the numerator.

Similarly, we have the sum of two second derivatives in the denominator, one for x sub 2 and one for x sub 3. And since we already know that the second derivative of the loss function equals p * 1 - p, we can plug in p sub 2 for the predicted probability for x sub 2, and we can plug in p sub 3, the predicted probability for x sub 3.

Now we just tidy everything up. Double bam! At long last, we see that gamma is equal to the sum of the residuals divided by the sum of p * 1 - p for each sample in the leaf. Okay, I know it seems like a long time ago, but we were trying to find the output value for this leaf.

So we did a ton of math and discovered that gamma sub 2,1 is the sum of the residuals divided by the sum of p * 1 - p for each sample that ended up in the leaf. Now we can plug in the residuals. Now we need to plug in the most recent predicted probabilities, P2 and P3 for X2 and X3.

Just like before, since we are building the first tree, the predicted probability for these samples is derived from F sub zero of X, the most recent log odds prediction. Note, since we are just starting out, the predicted probabilities are the same for all of the samples. However, after we build the first tree, they can be different.

Now just do the math. And the output value for leaf R sub two comma one is -0.77. Hooray! We made it through step two, part C. We calculated output values for each leaf in the tree. Now let's do part D. In part D, we make a new prediction for each sample.

Since this is our first pass through step two and M equals one, this new prediction will be called F sub one of X. The new prediction, F sub one of X, is based on the last prediction we made, F sub zero of X, plus the learning rate new times the output values from the first tree we made.

Note, this summation is there just in case a single sample ends up in multiple leaves. Also note, we've set the learning rate new to 0.8, which is relatively large. For more details about this, check out the StatQuest on the main ideas. Hooray! We've created F sub one of X.

Now we will use F sub one of X to make new predictions for each sample. We'll start with the first sample, X sub 1. The new prediction for X sub 1 starts with the last prediction, F sub 0 of X, which is 0.69. Plus 0.8 times the output value from the new tree, which is 1.5 because X sub 1 likes popcorn.

By the way, I love popcorn, too. Now, just do the math. The new log odds prediction for the first sample is 1.89, which is a better prediction than before because the odds are more in favor that this person will love Troll 2. Now, we'll calculate the new predicted log odds for the second sample, X sub 2.

The new log odds prediction for the second sample is 0.07, which is worse than before, but that's also why we build more than one tree. Now, we'll calculate the new predicted log odds for the third sample, X sub 3. The new log odds prediction for the third sample is 0.07, which is better than before.

Hooray! We made it through one iteration of step two. We started by setting little M equal to 1. Then we calculated pseudo residuals by plugging in the observed values and the latest predictions. And that gave us residuals. Then we fit a regression tree to the residuals and computed the output values, gamma sub J, M, for each leaf.

Lastly, we made new predictions for each sample, F sub 1 of X, based on the previous prediction, F sub 0 of X, the learning rate, new, and the output values, gamma sub J, M, from the new tree. Now, we set m equal to two and do everything over again.

A, calculate new residuals for the new predictions. B, create a new regression tree. C, calculate output values. And D, make new predictions. At the end of the second round, little m equals two and the new predictions, f sub two of x, are based on the predictions made by f sub one of x and the learning rate times the output values from the newest tree.

Now, in the interest of time, let's assume big m equals two so that we are done with step two. Note, in practice, m equals 100 or more. Now we are ready for gradient boost third and final step. If big m equals two, then f sub two of x is the output from the gradient boost algorithm.

Now, if we receive some new data, we would use f sub two of x to predict whether this person loves Troll 2. The predicted log odds that this person will love Troll 2 equals beep beep boop boop boop boop 3.4. The predicted probability that this person will love Troll 2 equals 0.97.

If we use a threshold of 0.5 for deciding if someone loves Troll 2, then since 0.97 is greater than 0.5, this person loves Troll 2. Triple bam! Holy freaking smokes, we made it through this whole algorithm. I can't believe it. We've done it for regression and now we've done it for classification.

Hooray! We've made it to the end of another exciting StatQuest. If you like this StatQuest and want to see more, please subscribe. And if you want to support StatQuest, well, consider buying one or two of my original songs or getting a t-shirt or a hoodie. The links to do this are in the description below.

All right, until next time, quest on.
