function [beta1, beta2, J_history] = trainNN(X, y, beta1, beta2, alpha, num_epochs)
%TRAINNN train the neural network model using backpropagation algorithm. It
%updates the weights, beta1 and beta2 using the training examples. It also
%generates the cost computed after each epoch.

% useful values
[n, ~] = size(X); % n is number of training examples
num_hidden = length(beta1(:,1)); % number of hidden units (bias not included)
num_output = length(beta2(:,2)); % number of output units

J_history = zeros(num_epochs,1); % stores value of the cost function J at each iteration

for epoch = 1:num_epochs
    % for each training example, do the following
    Jd = 0;
    for d = 1:n
        % ====================== YOUR CODE HERE ======================
        % Instructions: Perform a single gradient step on the weights beta1 and
        %               beta2. The key steps are indicated as follows
        %
        %


        %% Step 1: forward propagate to generate the network output

        Xd= [1 X(d,:)]'; % add bias unit to the input layer
        a0 = Xd; % input layer activation
        z1 = beta1 * a0; % hidden layer linear combination
        a1 = [1; sigmoid(z1)]; % hidden layer activation (add bias unit)
        z2 = beta2 * a1; % output layer linear combination
        a2 = sigmoid(z2); % output layer activation (network output)



        %% Step 2: for each output unit, calculate its error term
        % Recall that the number of output units is num_output

        d_out = a2 .* (1 - a2) .* (y(d) - a2);

        %% Step 3: for each hidden unit, calculate its error term
        % Recall that number of hidden units is num_hidden+1

        d_hidden = a1(2:end) .* beta2(2:end)' .* d_out .* (1 - a1(2:end));



        %% Step 4: update the weights using the error terms

        beta1 = alpha * d_hidden * a0' + beta1;
        beta2 = alpha * d_out * a1' + beta2;


        %% calculate the cost (Jd = SSE) per epoch
        Jd = Jd + (y(d) - a2)^2;
    end
    J_history(epoch) = Jd/(2*n);
end