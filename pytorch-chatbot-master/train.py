"""
This part imports the necessary libraries and modules needed for the code to run.
It imports numpy, random, json, PyTorch, the PyTorch neural network module (nn),
the PyTorch DataLoader and Dataset modules, custom functions from the nltk_utils module,
and the NeuralNet class from the model module.
"""
import numpy as np
import json
import torch
import torch.nn as nn
from torch.utils.data import Dataset, DataLoader
from nltk_utils import bag_of_words, tokenize, stem
from model import NeuralNet

# Loading and processing the data
"""
This part loads the data from the intents.json file, which contains a list of patterns for a chatbot to recognize. 
The data is then processed by tokenizing and stemming the words, removing stopwords, 
and creating a bag-of-words representation for each pattern. 
The tags for each pattern are also extracted and stored separately. 
Finally, the processed data is split into training input X_train and training output y_train arrays.
"""
with open('intents.json', 'r') as f:
    intents = json.load(f)

all_words = []
tags = []
xy = []
# loop through each sentence in our intents patterns
for intent in intents['intents']:
    tag = intent['tag']
    # add to tag list
    tags.append(tag)
    for pattern in intent['patterns']:
        # tokenize each word in the sentence
        w = tokenize(pattern)
        # add to our words list
        all_words.extend(w)
        # add to xy pair
        xy.append((w, tag))

# stem and lower each word
ignore_words = ['?', '.', '!']
all_words = [stem(w) for w in all_words if w not in ignore_words]
# remove duplicates and sort
all_words = sorted(set(all_words))
tags = sorted(set(tags))

print(len(xy), "patterns")
print(len(tags), "tags:", tags)
print(len(all_words), "unique stemmed words:", all_words)

# create training data
X_train = []
y_train = []
for (pattern_sentence, tag) in xy:
    # X: bag of words for each pattern_sentence
    bag = bag_of_words(pattern_sentence, all_words)
    X_train.append(bag)
    # y: PyTorch CrossEntropyLoss needs only class labels, not one-hot
    label = tags.index(tag)
    y_train.append(label)

X_train = np.array(X_train)
y_train = np.array(y_train)

# Defining hyperparameters
"""
This part defines the hyperparameters for the neural network, 
such as the number of training epochs, batch size, learning rate, 
input size (which is determined by the number of unique words in the training data), hidden layer size, 
and output size (which is determined by the number of unique tags in the training data).
"""
num_epochs = 1000
batch_size = 8
learning_rate = 0.001
input_size = len(X_train[0])
hidden_size = 8
output_size = len(tags)
print(input_size, output_size)

# Defining a custom PyTorch Dataset class
"""
This part defines a custom PyTorch Dataset class ChatDataset that will be used to load the training data 
into the neural network. The class defines a constructor that initializes the number of samples, 
training inputs, and training outputs, as well as __getitem__ and __len__ methods that are used to index 
and get the length of the dataset, respectively.
"""
class ChatDataset(Dataset):

    def __init__(self):
        self.n_samples = len(X_train)
        self.x_data = X_train
        self.y_data = y_train

    # support indexing such that dataset[i] can be used to get i-th sample
    def __getitem__(self, index):
        return self.x_data[index], self.y_data[index]

    # we can call len(dataset) to return the size
    def __len__(self):
        return self.n_samples

# Creating a DataLoader object
"""
This part creates a PyTorch DataLoader object train_loader that loads the training data into the neural network
"""
dataset = ChatDataset()
train_loader = DataLoader(dataset=dataset,
                          batch_size=batch_size,
                          shuffle=True,
                          num_workers=0)

device = torch.device('cuda' if torch.cuda.is_available() else 'cpu')

model = NeuralNet(input_size, hidden_size, output_size).to(device)

# Loss and optimizer
criterion = nn.CrossEntropyLoss()
optimizer = torch.optim.Adam(model.parameters(), lr=learning_rate)

# Train the model
for epoch in range(num_epochs):
    for (words, labels) in train_loader:
        words = words.to(device)
        labels = labels.to(dtype=torch.long).to(device)
        
        # Forward pass
        outputs = model(words)
        # if y would be one-hot, we must apply
        # labels = torch.max(labels, 1)[1]
        loss = criterion(outputs, labels)
        
        # Backward and optimize
        optimizer.zero_grad()
        loss.backward()
        optimizer.step()
        
    if (epoch+1) % 100 == 0:
        print (f'Epoch [{epoch+1}/{num_epochs}], Loss: {loss.item():.4f}')


print(f'final loss: {loss.item():.4f}')

data = {
"model_state": model.state_dict(),
"input_size": input_size,
"hidden_size": hidden_size,
"output_size": output_size,
"all_words": all_words,
"tags": tags
}
# save model
FILE = "data.pth"
torch.save(data, FILE)

print(f'training complete. file saved to {FILE}')
