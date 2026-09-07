---
title: "Python's Inner Working - Behind The Scenes"
url: "https://x.com/Harry_The_Nerd/status/2078116519029129646"
category: "Engineering Articles"
date: "2026-07-17"
description: "How Python executes code under the hood."
---

# Python's Inner Working - Behind The Scenes

> How Python executes code under the hood.
>
> 原文：[https://x.com/Harry_The_Nerd/status/2078116519029129646](https://x.com/Harry_The_Nerd/status/2078116519029129646) · 2026-07-17

![Cover image](https://pbs.twimg.com/media/HMtU-24bkAA20V5.jpg)

Most people write Python code, run it, and see the output. It feels simple. You type print("Hello"), hit run, and the words appear on screen. But a lot happens between typing that line and seeing the result. Let's walk through the entire journey, step by step, in plain and simple language.

## Step 1: You Write Source Code

Everything starts with a .py file. This file is just plain text. The computer does not understand plain text as instructions. It only understands machine code, which is a bunch of 1s and 0s specific to your CPU. So Python has to convert your readable code into something the machine can actually run.

## Step 2: Tokenizing (Lexical Analysis)

The first real step is called tokenizing. Python reads your source code character by character and breaks it into small pieces called tokens.

For example, this line:

x = 5 + 3

gets broken into tokens like:

- x (a name)
- \= (an operator)
- 5 (a number)
- \+ (an operator)
- 3 (a number)

Think of tokens as the "words" of your code. Just like a sentence is made of words, your code is made of tokens. This step does not care about meaning yet. It just identifies the pieces.

## Step 3: Parsing and Building the AST

Once Python has tokens, it needs to understand the structure and grammar of your code. This is where the parser comes in.

The parser takes the tokens and arranges them into a tree structure called an AST, which stands for Abstract Syntax Tree. This tree represents the grammatical structure of your code, similar to how a sentence has subjects, verbs, and objects.

For x = 5 + 3, the tree would roughly look like this in concept:

Assign ├── Target: x └── Value: BinOp ├── Left: 5 ├── Op: + └── Right: 3

This tree makes it easy for Python to understand what operation depends on what. If your code has a syntax error, like a missing colon or an unclosed bracket, this is usually the stage where Python catches it and throws a SyntaxError.

You can actually see this tree yourself using Python's built in ast module:

```python
import ast
tree = ast.parse("x = 5 + 3")
print(ast.dump(tree))
```

## Step 4: Compiling to Bytecode

Now that Python has a clean tree structure, it compiles this tree into something called bytecode. Bytecode is a low level, simplified set of instructions. It is not the same as machine code, but it is much closer to something a machine can process quickly.

This bytecode is stored in .pyc files inside a folder called \_\_pycache\_\_ when you import modules. This is why the second time you run a program, it sometimes starts a little faster. Python does not need to tokenize and parse again if the source file has not changed. It just reuses the saved bytecode.

You can view the bytecode of any function using the dis module:

```python
import dis

def add(a, b):
    return a + b

dis.dis(add)
```

This will output something like:

LOAD\_FAST a LOAD\_FAST b BINARY\_ADD RETURN\_VALUE

These instructions are simple stack based operations. Python is telling itself, load this value, load that value, add them, and return the result.

## Step 5: The Python Virtual Machine (PVM)

Here is the important part. Your CPU does not directly execute bytecode. It is executed by a system called the Python Virtual Machine, often abbreviated as PVM. This is basically a big loop written in C (since standard Python, called CPython, is written in the C programming language) that reads bytecode instructions one by one and performs the matching action.

This loop is sometimes called the "eval loop" internally. Think of it like a translator standing between your bytecode and your actual hardware. It reads an instruction like BINARY\_ADD, understands what it means, and then calls the correct C function to actually perform that addition using your CPU.

This is also the reason Python is considered an interpreted language. Unlike languages like C or Rust, which compile directly to machine code that your CPU runs on its own, Python always needs this virtual machine sitting in between, translating instructions on the fly.

## Step 6: Stack-Based Execution

Python's virtual machine uses something called a stack to keep track of values while executing instructions. A stack is a simple structure where the last thing you add is the first thing you take out, like a stack of plates.

Going back to our earlier example:

LOAD\_FAST a # push value of a onto the stack LOAD\_FAST b # push value of b onto the stack BINARY\_ADD # pop both values, add them, push result RETURN\_VALUE # pop and return the result

Every single operation in Python, no matter how complex your code looks, eventually breaks down into these tiny stack operations.

## Step 7: Frames and the Call Stack

Every time a function is called in Python, a new frame is created. A frame is like a small workspace that holds:

- Local variables for that function
- The bytecode being executed
- A pointer to where execution currently is
- A reference back to the calling frame

These frames stack on top of each other, forming what is called the call stack. If function A calls function B, and B calls function C, you get three frames stacked up. When C finishes, its frame is removed, and control goes back to B's frame, and so on.

This is also why deep recursion in Python can cause a RecursionError. Each recursive call adds a new frame, and there is a limit to how many frames can pile up.

## Step 8: Memory Management and Reference Counting

While all this execution is happening, Python is also managing memory behind the scenes. Every object in Python, whether it is a number, string, list, or custom class instance, has something called a reference count. This number tracks how many places in your program are currently pointing to that object.

```python
a = [1, 2, 3]   # reference count of the list becomes 1
b = a           # reference count becomes 2
del a           # reference count becomes 1
del b           # reference count becomes 0, memory is freed
```

When the reference count drops to zero, Python knows nobody needs that object anymore, so it frees the memory immediately.

## Step 9: The Garbage Collector

Reference counting alone has a weakness. It cannot handle situations where two objects reference each other, but nothing else references either of them. This is called a reference cycle.

```
class Node:
    def __init__(self):
        self.other = None

a = Node()
b = Node()
a.other = b
b.other = a
```

Even if you delete a and b from your code, they still reference each other, so their reference count never reaches zero on its own. To handle this, Python has a separate system called the garbage collector, which specifically looks for these cycles and cleans them up periodically.

## Step 10: The Global Interpreter Lock (GIL)

One more important piece is the GIL, short for Global Interpreter Lock. In standard Python (CPython), only one thread can execute Python bytecode at any given moment, even if your computer has many CPU cores.

This exists mainly to keep memory management, especially reference counting, safe and simple. Without the GIL, two threads could try to change a reference count at the same time and corrupt the data.

This is why Python threads are great for tasks that wait around a lot, like downloading files or reading from a database, but not great for tasks that need heavy CPU computation at the same time. For true parallel CPU work, people often use multiple processes instead of multiple threads, using a module like multiprocessing.

Putting It All Together (summary from start to finish):

You write source code in a .py file

Python tokenizes the code into small pieces called tokens

The parser builds an Abstract Syntax Tree from those tokens

The compiler turns that tree into bytecode

The bytecode gets cached in \_\_pycache\_\_ for faster future runs

The Python Virtual Machine reads the bytecode instruction by instruction

Each instruction runs using a stack-based system

Function calls create frames that stack on top of each other

Reference counting tracks and frees memory automatically

The garbage collector cleans up any leftover reference cycles

The GIL makes sure only one thread touches bytecode at a time

This process explains a lot of real behaviour you see every day as a developer:

- Why is Python slower than compiled languages like C, because of that extra virtual machine translation layer
- Why the first import of a large module can feel slow, but later ones are faster because of bytecode caching
- Why deep recursion fails with an error, because of the frame stack limit
- Why threads do not speed up CPU-heavy tasks the way you might expect, because of the GIL
- Why memory usually cleans itself up nicely, thanks to reference counting and the garbage collector working together

Python hides all of this complexity behind a clean and simple-looking language. But underneath that simplicity is a well-designed pipeline, turning your readable code into something a machine can actually execute, step by careful step.

That's all, folks...Cheers!!

Please like, comment, share & repost!!
